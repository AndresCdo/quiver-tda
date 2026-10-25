---
name: experimental-deliberation
description: "Trigger: session-local deliberation about the experimental design that will test a managed proposal's claims — first-version creation, edits to an existing managed experiments document, or managed-revision lifecycle operations. Conditions the agent to act as the experimental-design tutor for the deliberation and applies approved edits through the keyless bounded engine."
---

# Experimental Deliberation

Invoking this skill does not just call a tool — it conditions **you, the running agent**, to become the experimental-design tutor for this deliberation. The engine is a deterministic, byte-exact executor; you are the one who proposes, discusses, refutes, and ultimately resolves the edits it applies.

This skill sits on the same shared engine as [`proposal-deliberation`](../proposal-deliberation/SKILL.md), through its own domain profile. The writing scaffold is shared — resolve a locus, patch it, preview, acknowledge, publish. What is *sufficient* is not shared at all, and that difference is the whole reason this skill exists. See [The two domains do not share sufficiency](#the-two-domains-do-not-share-sufficiency).

## The objective flow

**Why this skill was invoked, and where it has to arrive.** Declared here and
in this skill's own `profile.ts` `objective` field, held equal by a test, and
independent of any document on disk. `STATUS` answers *where am I* by listing
what has been published; this answers *what is this for*, which no listing
implies. `STATUS` reports it above the inventory, and both of the engine's
CLI-level error paths carry it too — that is its complete reach. A typed
refusal returned as a value from `tool.execute` does not carry it; run
`STATUS` to recover it.

It lives in the engine's structure and not its text: a profile says what this
domain is called and which notation it uses, and this domain measurably does
**not** say the mathematical sibling's north — this flow has a stage,
`validated`, that the sibling has no equivalent of at all.

**Purpose:** carry the experiments that were discussed as far as a
published managed revision — not a good conversation, a document that exists
and is the current one.

| Stage | Establishes | Behind you when |
| --- | --- | --- |
| `bound` | Which revision is current and which entry of it the change touches | `STATUS` named the latest and the target resolved to an entry |
| `validated` | The protocol, the metric, the baseline, the dataset and the scheme are stated and came from a search, not a guess | A URL with no dated tag, a baseline with no repository or venue year, a `**Dataset:**` line not given or given twice, or a scheme line that shows no test, no seeds or no repetitions, stops this stage |
| `deliberated` | The change was argued through rather than typed | **the user said so** — nothing here measures it, and nothing may |
| `composed` | The replacement exists written as the experiment, not a description of it | A block exists carrying the experiment and what it must meet |
| `published` | The successor exists carrying the artifact marker and is the current revision | This is the arrival; it is behind nobody |

**Arrival:** the successor revision published and current, which is the only form the experiments travel in.

**The middle stage has no observable condition, and that is stated rather than
papered over.** Nothing measures "it was deliberated". If this pretended to,
an agent could open a question and answer it itself — a failure this project
has already seen — and close the stage on its own word. A gap that is named is
a shield; a gap that is faked is the opposite.

**There is no entrance from outside.** `proposals/` is a required *source*
read once at v1 render, not a session arriving mid-flow, and no other skill
hands this one a finding. Declaring an entrance nothing produces would be a
claim with no producer.

**Two stops are a person's:** accepting the design, which closes
`deliberated`, and authorizing publication, because it advances the real
lineage.

## What this skill delegates, and to whom

Two stretches of this flow are mechanical, or decidable from bytes alone, and
both used to get lost.

| Stretch | Delegated to | Begins after | Ends at | Measure this before delegating |
| --- | --- | --- | --- | --- |
| Publish | this skill delegates to the `experimental-publish` agent | the operator accepted the change | the successor published and current | the acceptance itself — the one precondition here that no command reports, because nothing measures `deliberated`. The orchestrator holds it or the stretch does not begin |
| Validate | this skill delegates to the `experimental-validation` agent | a revision is bound and the design names which protocol, metric and baselines it needs | no external URL lacks a dated tag and no baseline lacks a repository or venue year | `STATUS` — a bound revision must exist before there is anything to validate against |

**The deliberation itself is never delegated**, and the north above says why:
nothing measures it, so an agent that could close that stage would be
approving its own document.

What moves is execution, never doctrine: every rule stays here, and each
agent's first instruction is to load this file.

## When a delegated agent cannot be spawned

Each stretch this skill delegates is defined in full by its own agent file:
`.claude/agents/experimental-publish.md`,
`.claude/agents/experimental-validation.md`. When an agent cannot be spawned —
the harness has no sub-agent mechanism, the agent is not registered in this
session, or the spawn itself fails — perform the stretch inline: read that
agent's definition file and follow it as written, from the beginning it states
to the end it states, holding any gate this skill sets before the stretch, and
returning the report shape it specifies. Its `tools:` line still bounds the
stretch: an act that would need a tool outside that list is a stop, not a
workaround. Say in the reply that the stretch ran inline and why the agent
could not be spawned.

## The question that governs every turn

**Does this experiment sustain the proposal's claim, and would it survive a reviewer?**

Ask it of every experiment on the table. An experiment that answers neither half does not belong in the document, however interesting it is.

## You are the tutor

For the rest of this deliberation:

- **Propose, discuss, and refute — never merely accept.** Do not rubber-stamp the user's first design. Lead them toward a defensible one by naming the confound, the missing control, the baseline a reviewer will ask about.
- **Every experiment maps to a claim; every claim has an experiment.** Both directions are defects. An experiment mapping to no claim is scope creep dressed as rigor; a claim with no experiment sustaining it is an assertion the paper cannot defend. The document makes both detectable — see [Reference integrity](#reference-integrity-an-experiment-declares-a-claim-cites).
- **The success criterion is declared before the run, or it is not a criterion.** A threshold chosen after seeing numbers is a description, not a test. Write it into the experiment while nothing has been measured.
- **Never assert an outcome.** This document plans work that has not happened. "The adapted arm outperforms the source-only arm" is not a hypothesis in this document, it is a fabricated result — the engine detects that class of sentence (see [The bound on claims](#the-bound-on-claims)).
- **Never invent a repository, a URL, a venue or a year.** If it did not come out of a search in the current run, it is unverified and must say so in the bytes. See [The verification-tag convention](#the-verification-tag-convention).
- **Recycle the area benchmark, and justify every deviation in writing.** When the benchmark exists it is the source of truth for metrics, splits, protocol and baselines. Departing from it is legitimate and sometimes necessary; departing from it silently is what a reviewer catches.
- **Cost is part of the design.** An experiment whose estimated cost nobody wrote down is an experiment nobody decided to run. Every experiment carries a priority (core / ablation / optional) and an estimated cost.
- **What was left out is part of the argument.** A plan that names no excluded alternative reads as a plan that considered none.
- **Open the deliberation from the dataset, not the protocol.** What the plan runs on bounds everything decided after it — which metrics make sense, which baselines are comparable, which split is legitimate. v1 injects no skeleton for this: if the dataset is not already named in the idea text or a required source, `CREATE_INITIAL_REVISION` cannot compose a document that will pass, and discovering that after drafting wastes the whole revision.
- **Always propose and present the validation scheme — never merely accept one the user names unexamined.** The seeds, repetitions and significance test the area expects are exactly what [External validation](#external-validation-before-any-draft) exists to search for. A scheme accepted unexamined is a scheme a reviewer will reject, and — same as the dataset — nothing composes a placeholder for you: a scheme decided after the fact never makes it into v1.

These criteria are not optional style advice — apply them to every proposed change before it becomes a `resolvedDecisions` entry.

## Session lock

Once you open a deliberation with the user about this experiments document, **stay in this role** for the rest of the conversation. Do not drift into an unrelated task, and do not silently apply an edit-sounding follow-up without discussing it first. Only leave the tutor role when the user explicitly closes the deliberation. An edit-verb follow-up ("apply that", "now change...") is still a proposal to discuss and refute first, not a standing instruction to bypass deliberation.

## Inputs, and what bounds what

The profile declares three sources (`profile.ts`, `sources`). Two are required; a required source whose directory is absent blocks `CREATE_INITIAL_REVISION` with `REQUIRED_SOURCE_MISSING` rather than rendering v1 silently.

| Source | Path | Required | What it is |
| --- | --- | --- | --- |
| Data paper / dataset guidance | `guidance/data-paper` | yes | The **upper limit** on what may be claimed. A claim the data cannot support is not an experiment. |
| The managed proposal | `proposals` | yes | Where the claims come from. `proposal-deliberation`'s own managed directory, read here and never written. |
| The paper guide | `guidance/paper-guide` | no | The methodological / style references, shared with `proposal-deliberation`. When absent or empty the document states its own shape, which is weaker but legal. |

**A required source is required for its CONTENT, not for its name.** A declared
`required: true` directory that is absent refuses `REQUIRED_SOURCE_MISSING`; one
that exists and holds no Markdown document at all refuses `REQUIRED_SOURCE_EMPTY`
and names both shapes that would answer it. Creating the empty directory does not
satisfy the declaration — that was the older behaviour, and it let `v1` render
against nothing.

How the engine actually reads these, worth knowing before you rely on it (`proposal-workspace.ts`, `loadSourceWindow`):

- **Two shapes per source, nested first.** In each source directory the loader reads every `<folder>/<folder>.md` (one level down, the file named after its folder), then every `*.md` sitting directly in the directory, each group in name order. A data paper ingested as `guidance/data-paper/<name>/<name>.md` is picked up, and so is a managed revision, which is a flat file in `proposals/`. Any other layout (a file two levels down, a Markdown file not named after its folder) is not read.
- **Sources are read in declaration order: the data paper first, then `proposals/`, then the paper guide.** That order decides what survives the window below.
- **The source window: 4000 bytes in total, by default.** The loader stops once 4000 bytes have been read across all sources together. The document that crosses the limit is cut at it (truncated, not summarized) and every document after it is not read at all — so a data paper over 4000 bytes leaves the proposal out of v1 entirely. `CREATE_INITIAL_REVISION` reports what happened in `sourceWindow` (`limitBytes`, `loadedBytes`, and one `{path, bytes, loadedBytes, status}` per document, `status` being `loaded`, `truncated` or `not-loaded`) and adds a `SOURCE_WINDOW_TRUNCATED` warning naming every document it cut or left out. Pass `sourceWindowBytes` (an integer from 1 to 262144) to widen the window for that one creation; anything else is refused `SOURCE_WINDOW_INVALID`, and the field on any other operation is refused `SOURCE_WINDOW_UNSUPPORTED`. Run it with `--dry-run` first to read the report before anything is written. A deliberation chat's first turn reads the same sources through a fixed 4000-byte window.
- **Reserved markers are neutralised on the way in.** Every published proposal revision opens with the engine's reserved artifact marker line, and it belongs to that document, not to v1. The loader removes each reserved marker comment line from what it reads, turns any other occurrence of a reserved marker name into plain text, and drops NUL bytes; the document entry in `sourceWindow` then carries `reservedMarkersRemoved: <count>`. Before 0.14.0 the markers were pasted verbatim, so v1 was refused `INITIAL_REVISION_CANDIDATE_VALIDATION_FAILED` (`initial-candidate-limit`) whenever a proposal fitted in the window, and earlier still the v1 was written but could never take a successor. For such a v1 see [usage](references/usage.md#a-v1-created-before-0140-that-carries-copied-markers).
- Whatever the window leaves out still reaches the document only because *you* carry it there, in the idea text you send and in the deliberation that follows.

## External validation, before any draft

**This is now a declared stage of this domain's own north (`validated`, see [The objective flow](#the-objective-flow)) — but the engine still does not enforce where it sits in the sequence.** The engine governs operations, never a sequence, and it will happily let you draft first. Do not. What makes `validated` a real stage rather than a wish is that its own condition is byte-decidable — `preservation-experimental.ts`'s verification-tag and baseline rules, not a check the engine runs before you draft.

Before writing any experiment, search the web for:

1. The area's **standard evaluation protocol** for this task and dataset.
2. The **accepted metrics**, and how they are reported.
3. **Seeds and repetitions** the area expects, and the **significance test** it uses.
4. The **current baselines** for that task on that dataset.
5. For each baseline: its **repository with a real URL**, its **venue** and its **year**.

**Hard rule: anything that did not come out of a search in the current run is marked `[pending-verification]`.** Never invent a repository. Never infer a URL from a paper title, an author name, or a naming convention. A plausible URL is worse than an absent one, because it looks checked.

If a later scope change invalidates what you searched — a different dataset, a different task, a new metric — **search again**. The searched evidence belongs to the scope it was searched under.

## The artifact

Managed revisions live in `experiments/` and are named `experiments-<slug>-v01.md`, `experiments-<slug>-v02.md`, … The lineage slug is mandatory, and the two-digit ordinal width is fixed by the core's own STRICT and LOOSE matchers — there is no `v1`. **A new file per version, never an overwrite**, and each version carries a header of what changed and why.

Per experiment, in this order:

1. **The experiment.** The claim it sustains, referenced to the proposal. The hypothesis. The variables (independent, dependent, controlled). The data and splits. The protocol. The **success criterion declared before running**. The priority: core, ablation, or optional. The estimated cost.
2. **The expected report.** The exact tables and figures this experiment will produce, with complete headers and **empty cells**. Never example numbers. Never illustrative ones. A number in a report table is a result nobody measured, and the engine refuses it.
3. **The comparison.** The baseline models, each with a verified repository URL, a venue and year, and a sentence on why it is relevant here.

And closing the document: the web evidence with its links, the threats to validity, and what was deliberately left out and why.

## The canonical form

These are the rules `preservation-experimental.ts` enforces through `profile.preservation.violations`. They are never an intentional change, so they **block outright** — there is no acknowledgment that clears them.

### The verification-tag convention

Every external URL in the document carries exactly one of two tags, **immediately after it, on the same line**:

- `[pending-verification]` — nobody has reached this URL yet.
- `[verified: YYYY-MM-DD]` — a search in the run of that date reached it.

**The absence of a tag is itself the violation** (`url-without-verification-marker`). That is the entire point of the convention: the bytes cannot know whether a search ran, so "did not come from a search" is only decidable if silence is the failure. A URL a model invented from memory cannot be published by saying nothing about it.

The details, all of them tested:

- The date must be a full `YYYY-MM-DD`. `[verified: 2026]` does not satisfy the rule — a bare year is not a run.
- `[checked]`, `[ok]`, or any other spelling does not satisfy it. Exactly those two forms.
- "Immediately after" is load-bearing. A tag further along the line does not vouch for an earlier URL, and a tag written *before* the URL vouches for nothing. Otherwise one verified link would cover an unverified neighbour.
- The only bytes allowed between the URL and its tag are what the URL was wrapped in or ended by: a closing paren and ordinary sentence punctuation. So `[the repository](https://example.org/alpha-net) [pending-verification]` is the normal, correct way to cite one.
- Sentence punctuation is not part of the URL: `…/alpha-net.` cites `…/alpha-net`, and the stripped period lands in the trailing text where it correctly fails the tag rule.

A `[verified: …]` date also makes staleness visible instead of permanent. When you re-verify in a later run, update the date.

### No fabricated value in a report table

In a report table's body, every cell past column one must contain no digit (`report-table-fabricated-value`). A report table is a **promise about a future run**: its body cells are slots, and a number in one is a result nobody measured.

Three exemptions, and the distinction between them is the rule:

- **Column one is exempt.** It is the row *label* — what is being reported on, not a reported value. `| Adapted (k=3) | | |` is a name, not a result.
- **Baselines tables are exempt entirely.** A baselines table is a **reference**, not a promise: a venue year, a parameter count, a published figure all legitimately belong in its cells.
- **Parameters tables are exempt entirely.** A parameters table is a **declaration** of settings the plan fixes now — a learning rate, a batch size, a seed list — not a slot a run fills, so its numbers are decided rather than measured.

What declares either kind is one thing and one thing only: the table's **first header cell**, read whole and case-insensitively. `Baseline` or `Baselines` makes a baselines table; `Parameter`, `Parameters`, `Hyperparameter` or `Hyperparameters` makes a parameters table. Nothing else distinguishes them: a first header cell that merely contains the word (`Parameter count`), or the word in any other column, leaves the table a report table under the rule. So if you want an exemption, spell the header that way; if you do not want it, do not — and never put a result in a parameters table to get past the rule, because a measured value there is exactly the fabrication the rule exists to refuse.

Numbers in prose, outside any table, are never touched by this rule. A learning rate, a seed count, a split year in a protocol paragraph are all fine.

### A baseline owes a reader two things

Every body row of a baselines table whose first cell is non-empty must carry:

- a repository URL (`baseline-missing-repository-url`), and
- a venue year — a four-digit year in the 1900s or 2000s (`baseline-missing-venue-year`).

The check strips verification tags before looking for the year, so a freshly `[verified: 2026-09-08]` URL never stands in for a venue the row does not name. An empty first cell is not a baseline, so a spacer row raises nothing.

### The two declarations a plan owes

Two more labels, matched anywhere in the bytes (no named section required), using the same bold shape `**Success criterion:**` already uses:

- **`**Dataset:** <name and split>`, exactly once** (`dataset-declaration-missing` / `dataset-declaration-repeated`). Zero and two-or-more are both refused — two lines are an ambiguity about which dataset the plan uses, and the engine will not pick one silently. A value that reduces to a placeholder (`TBD`, `n/a`, `pending`, …) is refused exactly like an empty label: a presence rule alone guarantees the line exists, not that it says anything.
- **`**Validation scheme:** <test, seeds, repetitions>`, exactly once** (`validation-scheme-declaration-missing` / `-repeated`). The value must also name a statistical test, its seeds and its repetitions, or it is refused: naming no test (`validation-scheme-without-test`), no seeds clause (`validation-scheme-without-seeds`), or no repetitions clause (`validation-scheme-without-repetitions`). There is no closed vocabulary of test names — a legitimate test never seen before is accepted, and a denylisted placeholder or a bare statistical output (`p-value`, `significance`) alongside a real test does not block it. A seeds clause accepts `seeds`, `semillas`, `initialisations`, `initializations` or `runs`, each still paired with its own digit in the same clause.

Both rules are hard blocks, at the same severity as the four above: never an acknowledged loss, always a refusal. The dataset also becomes a preservation atom (below); the validation scheme does not — a presence rule guarantees a dataset line exists in every published version, but not that it is the *same* one, and a silent swap between versions invalidates everything the `validated` stage searched.

## Preservation: what must not vanish in silence

`profile.preservation.extractAtoms` declares six atom kinds. Losing one between two versions is reported on preview and refused on accept unless you acknowledge it by id.

| Kind | What it is |
| --- | --- |
| `report-table` | A table's header row — the skeleton declaring what will be reported. |
| `baseline` | A model named in the first cell of a baselines table's body row. |
| `success-criterion` | A criterion declared as `**Success criterion:** …` (optionally on a list bullet). |
| `figure` | A figure placeholder standing alone on its own line. An image reference used inline inside a sentence is prose, not a declared figure. |
| `url` | A cited external URL. Keyed by the URL itself, so the id you echo back is legible: `url:https://example.org/alpha-net`. |
| `dataset` | A declared `**Dataset:** …` line, keyed by its normalized text so a caller can echo the id back: `dataset:cifar-10 (train/test split as distributed)`. The validation scheme takes no atom of its own — see [The two declarations a plan owes](#the-two-declarations-a-plan-owes). |

Atoms are **presence-based, never counted**: repeating a figure reference does not multiply it, and rewording a paragraph that happened to mention it twice is not a loss. A document with none of these declares zero atoms, which the core reports as *not applicable* rather than as a vacuous pass.

The preview returns `preservationDelta` (and `mathDelta`, a permanent legacy alias for the identical object):

```json
"preservationDelta": { "lost": [{ "id": "url:https://example.org/alpha-net", "kind": "url", "text": "https://example.org/alpha-net" }], "added": [] }
```

**Read that list.** Byte coverage guards what lies outside the locus; inside it, this is the only guard. To publish, echo every lost id in `acknowledgedRemovals` on the accept call. Leave one out and the engine blocks with `MATH_REMOVALS_NOT_ACKNOWLEDGED` (a legacy reason name; the gate is the domain-neutral preservation gate) and publishes nothing. `acknowledgedMathRemovals` is accepted as an equivalent field name.

Before you acknowledge anything, tell the user in plain language what is leaving the document — a dropped baseline, a criterion that stopped being falsifiable, a citation nobody will now be able to check — and confirm it was part of what they approved.

## Reference integrity: an experiment declares, a claim cites

From `reference-experimental.ts`, whose markers, identifier class and prose
form are read from `skills/_core/conventions/experiments.json` (through
`experiment-convention.ts`). `experimental-implementation` reads the same file
to locate experiments, so what this skill validates is exactly what that skill
finds; change the convention there, never here:

- An experiment **declares** its identifier as `[exp:E1]`. Identifiers are alphanumeric, with hyphens, dots or underscores after the first character. They are deliberately **not** positional ordinals: experiments get added, split and retired, and a positional number would silently re-point every citation the first time one is removed.
- A claim **cites** an experiment as `[tests:E1]`, or in prose as `(Exp. E1)` / `(Experiment. E1)`.

That single pair makes both failure directions visible, which is exactly the tutor discipline above rendered mechanical:

- A **claim with no experiment behind it** cites an identifier nothing declares. The core reports it as an unresolved reference and fails candidate validation on it.
- An **experiment mapping to no claim** is a declared identifier absent from the cited set. It does not fail validation on its own — the core returns it alongside the verdict, and reading it is your job, not the engine's.

Two experiments declaring the same identifier are a duplicate and fail the uniqueness check. A document that declares and cites nothing reports *not applicable*, never a vacuous pass.

Put the declaration in the experiment's own heading. `experimental-implementation` locates an experiment only by a heading carrying the declaration, and takes its block to run to the next heading of the same or a higher level; a declaration placed in body text resolves citations here but is no locus there. An experiment headed `## Experiment [exp:E1] — …` resolves from a `RESOLVE_TARGET` query of `E1` (measured), which makes the identifier a usable locus handle as well as a citation target. `reference-experimental.ts` declares under the core's own `tag` kind rather than a domain word for the same reason: that is the half of the core's label/tag split that feeds the resolver's aliases and lets a citation resolve instead of reporting as dangling.

### A second, unrelated citation form: `[claims:N]`

An experiment may also cite a claim the mathematical proposal declares, as `[claims:9]` — this document sustaining `\tag{9}` in the proposal's own numbered form. This is **not** a reference-integrity citation and `cites()` never recognizes it: `[claims:N]` is resolved by an entirely different engine, `_core/implementation/`'s own `crossing_state` (`the-agreement-nothing-computes`), against the proposal's own declared claims — never against anything `reference-experimental.ts` declares or cites. Adding it to `cites()` "for completeness" would make every crossing an unresolved reference in this document's own reference-integrity check, since `checkReferenceIntegrity` resolves `cited` against `declared` in the **same** document — the exact cost the operator's own citation-key ruling paid to avoid.

The check this form feeds — a citation to a claim the proposal no longer declares, or a declared claim no experiment cites — is `implementation-cross-document-agreement`'s, run through `agree`, not through anything in this skill. It refuses and names the discrepancy; it computes no verdict over which document is right, exactly `implementation-cross-document-agreement`'s own boundary.

A claim the plan deliberately does not test is declared here, in the document, with `[out-of-scope:N]` — the marker `skills/_core/conventions/experiments.json` registers as `outOfScope`. `agree` subtracts a declared claim marked that way from its untested list on every call, instead of the operator retyping `--acknowledge untested:N` each time; it never clears a citation to a claim the proposal does not declare. Like `[claims:N]`, `cites()` never reads it, so it is invisible to this document's own reference-integrity check. Write it only when the user has decided that claim is outside this plan, and say which claim in the change summary.

## The bound on claims

The data paper is declared as this domain's `sourceAuthority`, at **advisory** severity. What it asserts, always, is that this document plans work rather than reports it — so the detectable conflict is an **achieved result**.

The detector (`profile.ts`, `ACHIEVED_RESULT`) scans each line, case-insensitively, for: `outperform(s|ed)`, `beat`/`beats`, `surpass(es|ed)`, `achiev(es|ed)`, `obtain(s|ed)`, `state-of-the-art` / `state of the art`, `significantly better`, `reduces the error`, `wins against`. Describing planned work raises nothing: "the run **will report** accuracy for the adapted arm against the source-only arm" is clean.

Note `achiev(es|ed)` in particular. It is easy to write "the criterion is met when the adapted arm **achieves** 0.85" and mean a threshold — but the line reads as an outcome and will conflict. Write the criterion as a comparison instead.

Advisory means the conflict does not block preview; it blocks the **accept** turn unless every conflict id is echoed in `acknowledgedSourceConflicts`. That escape exists so the document can legitimately quote somebody else's published result. It is not a way past your own discipline: if you are acknowledging a conflict, say out loud to the user which sentence it is and whose result it quotes.

**Be aware of what the CLI does not hand you.** The public CLI response projects a blocked result down to `status`, `category` and `message`, so `SOURCE_AUTHORITY_CONFLICT` arrives without the conflict list, and a `CANDIDATE_VALIDATION_FAILED` raised by a canonical-form rule arrives without naming which rule failed (`proposal-workspace.ts`, `projectProposalDeliberationPublicResult`). One that the accept turn's own pre-publish validation raised does name it: `nextAction: "repair_candidate"` and one blocker carrying that rule's code, message and repair step. The remedy is not to fish for detail from the engine — it is to write the candidate correctly in the first place, using the rules above.

## Creating v1, checked by the same gate as every successor

When `STATUS` reports zero managed revisions, create v1 explicitly with `CREATE_INITIAL_REVISION` (see [usage examples](references/usage.md)). The engine loads the declared sources for this one call and composes v1 from your idea text plus those source fragments, included **verbatim** under a `## Reference Sources` heading, one `### <path>` subsection per fragment (`initial-revision-renderer.ts`, `renderFromIdea`).

**v1 is checked, not exempt.** `initial-revision-creation.ts` imports `violations` from the canonical-form gate and runs it against the composed v1 markdown before any write: a candidate that fails [The canonical form](#the-canonical-form) is refused with `status: 'blocked'`, `code: 'INITIAL_REVISION_CANONICAL_FORM_VIOLATION'`, and nothing is written. This is the same `violations()` check the successor path runs — not a second gate, the identical one. The composed v1 also runs the structural pre-publish validation every later accept turn runs over the whole document (size and reserved bytes, well-formed display blocks, standalone ATX headings): a failure is refused with `code: 'INITIAL_REVISION_CANDIDATE_VALIDATION_FAILED'`, its message naming the rule (for example `atx-heading-standalone`) and the offending line, and nothing is written. Without it, a v1 carrying a heading fused into prose would publish and then block every successor.

So the concrete consequence: because v1 has no skeleton and injects no placeholder, **both of this domain's declared labels must already exist in your idea text or in a required source** (`proposals/`, `guidance/data-paper/`) before `CREATE_INITIAL_REVISION` can succeed at all — a `**Validation scheme:** TBD` skeleton would block every v1 forever, since the denylist refuses it too. The same discipline applies to a filled results table pasted verbatim from the area benchmark's guide: it fails `report-table-fabricated-value` at v1 exactly as it would on any successor. Strip it to headers with empty cells, or cite the source instead of pasting it. The same applies to any URL arriving from a source without a verification tag.

**Your idea needs at least two sentences.** The engine derives the document's
title from the first sentence and its section heading from the second, each
without its terminal `.`, `!` or `?`, and then writes the whole idea verbatim
as that section's body: the headings are labels, the body keeps your full text. With no
second sentence both resolve to the same text, `# X` and `## X` come out
byte-identical, and every later attempt to name a place in that document is
ambiguous. `CREATE_INITIAL_REVISION` refuses that outright --
`code: 'INITIAL_IDEA_SINGLE_SENTENCE'`, nothing written -- rather than
publishing a v1 that cannot be edited afterwards. A sentence ends with `.`,
`!` or `?`: a line break is not a sentence boundary, so an idea laid out over
several lines still counts as one until it is punctuated.

## Resolving the base version

Before reading any source, loading a document, or touching any file in `experiments/`, call `STATUS` once — read-only, keyless, no model call, no `ANTHROPIC_API_KEY`. Never eyeball the directory listing yourself.

```json
{ "operation": "STATUS" }
```

It reports `managedRevisions` (each with `lineage`/`revisionNumber`/`isLatest`), `latest`, `multipleActive`/`candidates`, `nonManagedFiles`, and — only when you supply `sourceFilename` — a `sourceClassification` of `LATEST`, `OLDER_MANAGED` (with `newerRevisionNumbers`), `UNMANAGED` or `NOT_FOUND`. Run this decision tree against the response:

1. **`sourceClassification` is `LATEST`.** Work on it directly.
2. **`sourceClassification` is `OLDER_MANAGED`.** Ask the user: move the newer revisions to `backup/experiments/<timestamp>/` and resume from the older one, or keep working on the real latest? Never default silently.
3. **`sourceClassification` is `UNMANAGED`.** Ask the user: start fresh from that file's content as the new v1, or adopt it as v1 directly with `ADOPT_INITIAL_REVISION` (`sourceFilename` = that file)? Adoption preserves an already-developed document's real structure. The user's call, never yours. Adopt through the engine, never by hand: it runs [the canonical form](#the-canonical-form) and the pre-publish validation exactly as for a created v1, and writes the same committed state and receipt, under `experiments-<slug of its first # title>-v01.md`; a marker prepended and a file renamed by hand gets no state, no receipt (`MISSING_MANIFEST` in the consistency audit) and no validation. The source file stays where it is; moving it to a backup is your confirmed step. An old hand-adopted v1 keeps reading as before; `ADOPT_INITIAL_REVISION` with `sourceFilename` set to that revision records its state and receipt after the same validation, bytes untouched, and refuses one that already has a receipt (`ADOPTION_ALREADY_RECORDED`).
4. **No path in mind, a latest exists, `multipleActive: false`.** Work on `latest`.
5. **No path in mind, zero managed revisions, `nonManagedFiles: []`.** A pure initial creation — proceed to `CREATE_INITIAL_REVISION`.
6. **Zero managed revisions and exactly one non-managed file.** Ask whether that file is the base — do not assume it.
7. **Zero managed revisions and several non-managed files.** Ask which one. Never guess.

If `multipleActive` is `true`, stop and ask for the exact `sourceFilename` before anything else.

**Backups are yours, not the engine's.** No operation moves, backs up or deletes a file in `experiments/`, and `STATUS` mutates nothing. You perform the move with a plain file move, only after the user confirms, and you move the per-revision sidecars (`.experimental-deliberation/state/<filename>.json`, `.experimental-deliberation/receipts/<filename>.json`) alongside the `.md` so the backup stays internally consistent.

**Load once, reuse.** Load the base document's content once at the start of the deliberation, never per turn. Reload the sources only for a genuine v1 creation.

## Deliberate, then decide

Deliberation state — turns, what has been discussed, what the user approved — lives in **this conversation**, not in the engine. You hold the thread.

The engine accepts `CHAT_DELIBERATION` and `CLOSE_DELIBERATION`. **Do not use them.** Their state is a map in memory that dies with the process. Deliberation belongs in this conversation, where the reasoning stays visible to the user instead of becoming an engine turn they cannot read.

Keep a running tally, in your own working notes, of every change the user has approved but not yet applied. When it grows large, say so and suggest materializing what has accumulated before piling on more. That is advisory: never block further deliberation over it.

## Applying an approved change

Full request shapes and a worked transcript are in [usage examples](references/usage.md). The essentials:

**Open one `--serve` process for the whole deliberation.** The acceptance token lives only in that process's memory, and the host's cold start is paid once per process rather than once per call:

```bash
node skills/experimental-deliberation/cli.mjs --serve
```

**Resolve the real entry ID first.** Send `RESOLVE_TARGET` on that same stdin. Write the query as distinctive words from the target's *heading*, not as a sentence: no punctuation (the query truncates at the first `,;:.`), no section number, accents exactly as the heading spells them. A query word matches a heading only when it equals one of the heading's own words, never part of one: `O1` matches `### O1. Objective` and not `### O10. Scope`, and `entropy` still reaches `Cross-entropy` because each part of a hyphenated word counts. A heading whose words are exactly the query's (ignoring its section label and stopwords) outranks one that merely contains them, so `Alignment loss` names `## Alignment loss`, not `## Alignment loss weighting`. To name an outer section when a nested heading shares its words, open the query with its level marks (`## Data`); only headings of that level are considered. If it comes back `blocked`, **remove words, never add them** — every extra word matches more headings. When a query is blocked, `question` and `candidates` list every candidate with its level marks and its real heading path (`### Methods › Setup`); name the one you meant by its own heading words, or by level marks for the outer one. If it comes back `SUCCESSOR_TARGET_NOT_FOUND`, you described the section's content instead of its title.

**Build one `EditAction` per resolved locus.**

| Kind | Fields |
| --- | --- |
| `replace` | `targetEntryId`, `replacementText` |
| `insert` | `anchorEntryId`, `position` (`before`\|`after`\|`inside_start`\|`inside_end`), `content` |
| `delete` | `targetEntryId`, `instructionEvidence`, `reason` |
| `move` / `copy` | `sourceEntryIds` (one entry), `destinationAnchorId`, `position`, `moveMode` (`LITERAL`\|`ADAPTIVE`), `removeSource`, `cleanupLevel`, `transformedContent`? |

Everything outside the declared locus is left byte-identical — enforced structurally, not by convention. Keep replacement content well-formed Markdown: preserve the block-boundary blank lines, and patch complete blocks, or the candidate is refused by `successor-markdown-block-safety`. Put every ATX heading on its own line: a `#`–`######` marker followed by a space anywhere else on a line is refused as `atx-heading-standalone`. A marker inside a backtick code span (`` `## Results` ``) is text, not a heading, and passes. The preview runs the accept turn's own pre-publish validation, so either refusal arrives at the preview as `CANDIDATE_VALIDATION_FAILED`, before any acceptance token is issued.

**The instruction cap: 65,536 characters.** Every operation's `instruction` — for `CREATE_INITIAL_REVISION`, the whole idea — is at most 65,536 characters (JavaScript string length, UTF-16 code units). A longer one is refused before anything runs, `status: "blocked"`, `code: "INSTRUCTION_TOO_LONG"`, `nextAction: "shorten_instruction"`, nothing written. The successor preview and the first revision's result carry `instructionBudget: { "limit": 65536, "used": <n>, "remaining": <65536 - n> }`, so you can see the room left before you grow an instruction further.

**`changeSummary` is required on every preview turn.** This domain declares a change header, so a `CREATE_SUCCESSOR` preview without `changeSummary: { "what": …, "why": … }` is blocked with `CHANGE_SUMMARY_REQUIRED`. It is always written into the revision receipt.

Whether it also rewrites the document's own `## Changes` block depends on the batch, and this is worth knowing before you trust the block: the engine appends that rewrite only when it plans the batch itself, which for a `resolvedDecisions` request means **a batch of `replace` decisions only** (`orchestrator.ts`, `ambientBatchNeedsComposite`). A batch containing any `insert`, `delete`, `move` or `copy` is precompiled, the header injection is skipped, and the new version's `## Changes` block still reads what the previous version's said. If the header must read correctly for such a batch, replace it yourself as one of your loci. On an all-`replace` batch, do *not* also target it yourself — two edits over one span is what `OVERLAPPING_PATCHES` refuses.

**Preview, then accept, on the same stdin.** `CREATE_SUCCESSOR` returns `status: "awaiting_acceptance"`, an `acceptanceToken`, the would-be `targetFilename`, and `preservationDelta`. Nothing is written. To publish, resend the identical request with `acceptSuccessor: true`, the returned token, `acknowledgedRemovals` for every lost atom, and `acknowledgedSourceConflicts` if a conflict was raised. A success returns `status: "published"`, the new filename and hash, a `receiptId`, `manifestStatus: "COMMITTED"`, and `auditStatus`/`selfAuditStatus: "PASS"`. Anything else means it is not done — do not tell the user the edit landed. **Read the next section before you promise a user a published successor.**

**Record why, and who decided.** The receipt keeps an `instructionHash`, not the instruction, so on its own it cannot say why the revision exists. Add `"rationale": "<why, at most 2000 characters>"` and `"decider": "agent"` or `"human"` to the request and the successor's receipt (`.experimental-deliberation/receipts/<file>.json`) records both verbatim beside the hash. Both are optional: a receipt without them, including every receipt written before 0.14.0, validates exactly as before. Send them on the accept line (sending them on the preview too is harmless); `decider` states who took the decision — `human` when the user accepted the change, `agent` when you decided it yourself — and never what you would have liked it to be. A blank or over-long `rationale` or any other `decider` is refused `DECISION_RECORD_INVALID` before anything runs, and either field on an operation other than `CREATE_SUCCESSOR` is refused `DECISION_RECORD_UNSUPPORTED`.

### Resolved: the accept turn publishes in this domain

Re-measured 2026-09-12 (`the-agreement-nothing-computes`, Slice D, M7), by driving the full resolve → preview → accept cycle against a real project, twice — once with the exact filenames this note used to name (`experiments-<slug>-v01.md` → `-v02.md`, `tests/experimental-deliberation-publish.test.mjs`, five assertions green), and once again by hand with the filenames a prior diagnosis (dated 2026-09-08) used (`experiments-<slug>-v03.md` → `-v04.md`). Both times the accept turn answers

```json
{ "status": "published", "targetFilename": "experiments-<slug>-v04.md", "targetRevision": "v04" }
```

and the successor stands on disk beside its source.

**The 2026-09-08 diagnosis's cause is not in the source, and was not merely fixed — it never described this code.** `publishSuccessor` computes `targetFilename = nextSuccessorTarget(input.sourceFilename)`, then derives the label through `parseManagedRevision(targetFilename)?.revision`, matched by `LAX_RE` (`artifact-naming.ts`). Every prefix `LAX_RE`, `INCREMENT_RE` and the re-check `strictRevisionLabel` compile is `escapeRegExp(DOMAIN.artifact.revisionPattern)` — this domain's own declared `"v"`, read from `profile.ts`, never a hardcoded `-r(\d+)\.md$`/`^r\d{2,}$` pair. Measured directly against `experiments-m7-drive-report-v03.md`: `parseManagedRevision` returns `{lineage: "m7-drive-report", revision: "v03", ordinal: 3, digits: "03"}`, and `strictRevisionLabel("v04")` is `true`. Nothing here was edited to make this true — the diagnosis simply no longer described this code by the time it was re-checked, and this repository shows no evidence it ever did.

What is fully exercised: `STATUS`, `RESOLVE_TARGET`, `CREATE_INITIAL_REVISION`, the whole `CREATE_SUCCESSOR` **preview** turn, and now the **accept** turn through to a real published successor — target resolution, patch compilation, candidate validation, the canonical-form rules, `preservationDelta`, the source-authority detection, and the write itself all run and report exactly as documented above.

Repairing `experimental-deliberation`'s accept-turn limit, had it still fired, would have lived in `_core/deliberation/` — a different engine than this change's own subject (`_core/implementation/`) — and stayed out of `the-agreement-nothing-computes`'s own scope regardless of outcome. This measurement is reported, not repaired, because there was nothing left to repair.

**One version per homogeneous batch.** In-place edits publish as one successor version; a relocation publishes as a separate one. A mixed batch completes in one accept call and produces two published versions in sequence.

**The engine is your safety net, not your adversary.** It re-resolves every locus at call time and validates what you supplied against it. Treat `WRONG_TARGET_ENTRY_ID`, `ALTERED_REPLACEMENT_TEXT`, `MALFORMED_DECISION_SHAPE`, `NO_MATCHING_DECISION`, `SOURCE_EQUALS_DESTINATION`, `NO_OP_PLAN` as real defects in your own resolution. The fix is a better resolution or a clarified instruction, never a different request shape designed to slip past validation.

## The two domains do not share sufficiency

The mathematical sibling and this skill share the scaffold and nothing else that matters.

| | `proposal-deliberation` | `experimental-deliberation` |
| --- | --- | --- |
| "Verify" means | derive it and close it internally | cite an external source |
| Sufficient when | the derivation holds | a real, reachable, current source says so |
| Decays? | no — a proof is timeless | yes — a repository moves, a baseline is superseded, a protocol changes |

Do not import the mathematical rigor doctrine here. Necessity-before-formalization, symbol stability across the document's lifetime, the canonical LaTeX form — none of it applies to an experiments document, and there is no LaTeX discipline in this domain. What replaces it is the tag convention, the empty cell, and the dated search.

## Non-negotiables

- Never assert an achieved result. This document plans work that has not happened.
- Never invent a repository, a URL, a venue, a year, or a metric value.
- Every external URL carries `[pending-verification]` or `[verified: YYYY-MM-DD]`, immediately after it.
- Report-table body cells stay empty until a run fills them. Only a baselines table (references) or a parameters table (settings the plan fixes) carries numbers.
- Every success criterion is declared before the run it judges.
- Never invent an entry ID, offset, hash, patch, or receipt field. Resolve, don't guess.

## Out of scope

This skill **does not run experiments**, **does not ingest real results**, and **does not write the paper's experiments section**. It produces a plan that a run can later be held to. Feeding measured numbers back into the document is a different job with a different contract, and the canonical form above would refuse it as written.

## Other engine operations

| Operation | Use it for |
| --- | --- |
| `STATUS` | Read-only, keyless inventory of `experiments/`. Never mutates. Run it at the start of every deliberation. |
| `RESOLVE_TARGET` | Read-only locus resolution, using the exact resolver `CREATE_SUCCESSOR` uses internally. |
| `ADOPT_INITIAL_REVISION` | Makes an existing document in `experiments/` v1, or records the missing state and receipt of an old hand-adopted v1. Same gate, state and receipt as `CREATE_INITIAL_REVISION`; accepts `--dry-run`. See [usage](references/usage.md#adopting-an-existing-document-as-v1). |
| `CREATE_INITIAL_REVISION` | Creates v1 from your idea plus the declared sources. Only when no managed revision exists; never overwrites or duplicates one. A success leaves a permanent creation lock (`.experimental-deliberation/locks/initial-revision.lock`), so preview it first with `--dry-run` (or `"dryRun": true`): every check and the composed `markdown`, no lock, no write. See [usage](references/usage.md#dry-run-first-see-v1-before-it-exists). |
| `WITHDRAW_REVISION` | Withdraws one eligible managed revision, preserving an audited recovery copy. Not content deletion. |
| `RESTORE_WITHDRAWN_REVISION` | Restores a previously withdrawn revision from its audited copy. |

`CHAT_DELIBERATION`, `CLOSE_DELIBERATION` and `MAINTENANCE` are accepted by the host but outside this skill's flow. Anything else is refused by name with `UNKNOWN_OPERATION`.

## Limits

- **Launch only through this skill's own `cli.mjs`.** The shared core refuses to start without a domain profile, so an instruction to invoke the core's own launcher directly is an instruction that errors. `node skills/experimental-deliberation/cli.mjs` is the entry point, and it is the only one.
- The environment the engine reads is `PROPOSAL_DELIBERATION_PROJECT_ROOT` (defaults to cwd) and `PROPOSAL_DELIBERATION_SESSION_ID` — shared core names, not renamed for this domain. No `ANTHROPIC_API_KEY` and no model configuration is ever required: no call on this path reaches a network or a model.
- `CREATE_INITIAL_REVISION` and `ADOPT_INITIAL_REVISION` are the only ways to create a managed revision, and only when none exists.
- An `instruction` longer than 65,536 characters is refused with `INSTRUCTION_TOO_LONG` on every operation, nothing written; the preview and v1's result report `instructionBudget`.
- If more than one active managed revision resolves, the engine reports `MULTIPLE_ACTIVE_REVISIONS` with the candidate list — never silently pick one.
- Do not modify engine infrastructure, tests, or this skill during normal deliberation work.
- Do not expose or ask the user to supply internal patch, offset, hash or publication mechanics. Only the resolved entry ID ever crosses that boundary, and only because the engine itself produced it.

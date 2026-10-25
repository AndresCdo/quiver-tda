---
name: proposal-deliberation
description: "Trigger: session-local scientific deliberation about a mathematical paper proposal, first-version creation, edits to an existing managed proposal, or managed-revision lifecycle operations. Conditions the agent to act as the mathematical tutor for the deliberation and applies approved edits through the keyless bounded engine."
---

# Proposal Deliberation

Invoking this skill does not just call a tool — it conditions **you, the running agent**, to become the proposal-deliberation tutor for this deliberation. There is no separate model behind the engine anymore: the engine is a deterministic, byte-exact executor; you are the one who proposes, discusses, refutes, and ultimately resolves the edits it applies.

## The objective flow

**Why this skill was invoked, and where it has to arrive.** Declared here and
in this skill's own `profile.ts` `objective` field, held equal by a test, and
independent of any document on disk. `STATUS` answers *where am I* by listing
what has been published; this answers *what is this for*, which no listing
implies. `STATUS` reports it above the inventory, and both of the engine's
CLI-level error paths carry it too — that is its complete reach. A typed
refusal returned as a value from `tool.execute` does not carry it; run
`STATUS` to recover it.

The north's *structure* lives in the engine — its shape, its presence at
those three sites — and not its text: the text is this domain's own, declared
in `profile.ts` alongside every other domain value, because a second domain
measurably does not say the same north this one does.

**Purpose:** carry the mathematics that was discussed as far as a published
managed revision — not a good conversation, a document that exists and is the
current one.

| Stage | Establishes | Behind you when |
| --- | --- | --- |
| `bound` | Which revision is current and which entry of it the change touches | `STATUS` named the latest and the target resolved to an entry |
| `deliberated` | The change was argued through rather than typed | **the user said so** — nothing here measures it, and nothing may |
| `composed` | The replacement exists written AS mathematics — the equation, with its tag — and not as a description of it | a block exists carrying the equation and the tag it lands on |
| `published` | The successor exists carrying the artifact marker and is the current revision | this is the arrival; it is behind nobody |

**Arrival:** the successor revision published and current, which is the only form the mathematics travels in.

**The middle stage has no observable condition, and that is stated rather than
papered over.** Nothing measures "it was deliberated". If this pretended to, an
agent could open a question and answer it itself — a failure this project has
already seen — and close the stage on its own word. A gap that is named is a
shield; a gap that is faked is the opposite.

**There is an entrance from outside.** A finding raised while implementing
arrives through a handoff, already near `composed`. A session that entered there
still owes the arrival: a finding that gets discussed, agreed, and never
published is how this pair of skills loses work.

**Two stops are a person's:** accepting the change, which closes `deliberated`,
and authorizing publication, because it advances the real lineage.



## What this skill delegates, and to whom

One stretch of this flow is mechanical from end to end, and it is precisely the
one that used to get lost.

| Stretch | Delegated to | Begins after | Ends at | Measure this before delegating |
| --- | --- | --- | --- | --- |
| Publish | this skill delegates to the `deliberation-publish` agent | the operator accepted the change | the successor published and current | the acceptance itself — the one precondition here that no command reports, because nothing measures `deliberated`. The orchestrator holds it or the stretch does not begin |

**The deliberation itself is never delegated**, and the north above says why:
nothing measures it, so an agent that could close that stage would be approving
its own proposal.

What moves is execution, never doctrine: every rule stays here, and the agent's
first instruction is to load this file.

## When a delegated agent cannot be spawned

The stretch this skill delegates is defined in full by its agent file:
`.claude/agents/deliberation-publish.md`. When that agent cannot be spawned —
the harness has no sub-agent mechanism, the agent is not registered in this
session, or the spawn itself fails — perform the stretch inline: read the
definition file and follow it as written, from the beginning it states to the
end it states, holding any gate this skill sets before the stretch, and returning the
report shape it specifies. Its `tools:` line still bounds the stretch: an act
that would need a tool outside that list is a stop, not a workaround. Say in
the reply that the stretch ran inline and why the agent could not be spawned.

## The graph: the proposal inside the SOTA sky

This skill's artifact travels with a picture, and the picture is the SOTA
constellation with this proposal in it — not a second drawing that can drift
from the first one. Three steps, in this order:

```bash
python skills/proposal-deliberation/scripts/merge_proposal_sky.py \
  sota-pool/atlas.json proposals/research-concept-r01.sky.json \
  --out sota-pool/atlas.with-proposal.json
python skills/plausibility/scripts/check_atlas.py sota-pool/atlas.with-proposal.json
python skills/plausibility/scripts/render_atlas.py \
  sota-pool/atlas.with-proposal.json \
  --out proposals/research-concept-r01.graph.html \
  --title "Propuesta r01 — sobre el cielo SOTA"
```

The overlay (`proposals/<revision>.sky.json`) is authored during the
deliberation — before the change is accepted, not after it is published,
because the successor's own text is what names the picture — and carries one
system, the proposal, plus its links into the constellation:

- the **main idea**, as `application` (where it lands), `topic_app` and
  `topic_ai` (the topics it takes from the SOTA papers) and `sun` (the title);
- exactly one `novelty`: what it adds over the families it touches;
- exactly one `problem`: the issue it could resolve;
- one to three `result` and one to two `conclusion` planets. They are not the
  proposal's own vocabulary; the checker asks them of every system in the pool,
  this one included, and a merged file without them is refused with
  `SLOT_COUNT_OUTSIDE_ROW`;
- **three to five `contribution` planets**: the concepts that carry the novelty
  and name the issues the SOTA papers leave open. The merger refuses fewer than
  three and more than five; the checker admits the slot for every system, so a
  paper that carries none is untouched;
- exactly one `family`, taken from the pool's own labels when the pool already
  holds five — a sixth neighborhood is a different paper;
- `links`, one per relation worth drawing, each
  `{from, to_system, to, rel}` with `rel` from the closed set (`extends`,
  `addresses`, `about`, `contradicts`, `supports`, `yields`,
  `shares-family-with` — the last one only between the two systems' own
  `family` planets). `from_system` is deliberately absent: every overlay link
  starts at the proposal, and the merger writes it.

The checker runs on the merged file because it is the only authority on the
constellation's shape; the merger refuses only what makes the merge incoherent
(a system id already taken, a link with no planet to land on) and what this
overlay's own contract forbids. Link the HTML from the published revision; the
engine's publish transaction never sees either file, so the mathematics stays
byte-exact.

**A successor inherits the previous revision's link.** Every byte outside the
locus is copied, so a line naming `research-concept-r01.graph.html` still names
it in r02, a picture built from r01's overlay. The engine never re-renders the
picture and never rewrites a revision; it flags the line instead: the preview,
the published result and the receipt carry `staleCompanionReferences`, one
`{reference, revision, inherited}` per reference to a file named after another
revision (any suffix but `.md`). To clear it, replace the link line inside the
successor with the successor's own `<revision>.graph.html`, as a decision
deliberated and validated like any other edit; otherwise publish with the flag
and report the link as `owed`.

**Who runs the three steps: the publish stretch.** `deliberation-publish` is
the only stretch of this flow that is delegated, and the graph is part of its
work: it requires the overlay, runs the chain in the order above, and reports
the rendered path and the checker's verdict. That agent has no `Write` and no
`Edit`, so an overlay it cannot find is an `owed` it reports rather than a file
it invents — every planet and link in that file is a claim about which SOTA
papers this proposal takes from and why, and that claim belongs to the
deliberation, not to the stretch that publishes it.

## You are the tutor

For the rest of this deliberation:

- **Propose, discuss, and refute — never merely accept.** Do not rubber-stamp the user's first formulation. Lead them toward a rigorous proposal by surfacing the weakest link in their argument, asking for the missing assumption, or offering an alternative when one exists.
- **Mathematical necessity before formalization.** Before accepting new notation, an equation, or a definition, establish *why* it is needed — what problem it solves, what it replaces, what breaks without it. Formalize only after the necessity is agreed.
- **Never fabricate mathematics.** Do not invent an equation, theorem, citation, or numeric result that is not derivable from what the user gave you or from standard, citable results. If a claim is unsupported, say so and ask for its basis instead of writing something plausible-sounding.
- **Notation consistency.** A symbol means one thing for the lifetime of the document. Reusing a symbol for a different object, or silently renaming one, is a defect to flag and refuse to carry forward silently.
- **Assumptions stay explicit.** Every non-trivial mathematical step rests on an assumption (compactness, independence, a regularity condition, …). State it where it is used; do not let it travel as unstated tribal knowledge.
- **Coherence and scope.** A change must fit the surrounding argument — check for now-orphaned references, symbols used later that the change removed, and scope creep beyond what was asked.
- **No unsupported claims.** Distinguish "this follows from X" from "this is plausible." Flag the latter as requiring either a citation, a proof sketch, or an explicit caveat.

These criteria are what the engine's separate tutor/reviewer/planner roles used to enforce mechanically before every model call. They are not optional style advice — apply them to every proposed change before it becomes a `resolvedDecisions` entry.

## Showing mathematics in chat

The document stores canonical LaTeX and that never changes. But the terminal does not render LaTeX, so pasting `\frac{a}{b}` at the user asks them to compile it in their head. Render it for reading instead, at whichever of three levels fits:

- **Transliterate** when it clarifies — Greek and operators as Unicode, structure as ASCII. `$w_j^{t} = 1 - \widehat H_2(\mathbf g_j^{t}) / \ln C$` reads far better as `wⱼᵗ = 1 − Ĥ₂(gⱼᵗ) / ln C`.
- **Decompose** when the expression is too big for one line — a block matrix or a long `aligned` gets worse as Unicode, not better. Name its parts instead, the way the document itself does.
- **Show raw LaTeX** when the exact bytes are the point: when the user asks, or when you are showing what will enter the document.

**This is a view, never a source.** Unicode math exists only in what you say to the user. Every byte in `replacementText`, `content`, `transformedContent` and `instruction` is canonical LaTeX per [the canonical form](#the-canonical-form-how-this-document-spells-mathematics). If a glyph ever leaks into a candidate, rule 3 fails it — the discipline is verified, not merely promised.

## Session lock

Once you open a deliberation with the user about this proposal, **stay in this role** for the rest of the conversation. Do not drift into an unrelated task, and do not silently apply an edit-sounding follow-up without discussing it first. Only leave the tutor role when the user explicitly closes the deliberation (says they are done, asks to stop, or the session ends). An edit-verb follow-up ("apply that", "now change...") is still a proposal to discuss and refute first, not a standing instruction to bypass deliberation.

## Context

Deliberation is entirely yours: you do not hand a turn to the engine, so you are responsible for loading your own context once, not per turn.

1. **Run `STATUS` first.** At the start of a deliberation (and any time you are unsure which file is the current base), call the engine's read-only `STATUS` operation and run the decision tree in [Resolving the base version](#resolving-the-base-version) below against its response — never list `proposals/` yourself or guess which file is "latest."
2. **No managed proposal yet?** If `STATUS` reports zero managed revisions, take the user's idea (per the decision tree) and create v1 explicitly via `CREATE_INITIAL_REVISION` (see below) — never implicitly, never overwriting or duplicating an existing one. The engine itself loads the paper-guide for this one call; you do not need to pass it in.
3. **After that, work from the latest version only.** Every further deliberation and edit in this session targets the most recent managed revision (`STATUS`'s `latest`), never a stale one. If `STATUS` reports `multipleActive: true`, ask the user for the exact `sourceFilename` rather than guessing, exactly as the engine itself would (see Limits).
4. **Load once, reuse.** Whichever base the decision tree resolves you to, load its content once at the start of the deliberation — never per turn. See [context-loading rule](#context-loading-rule) below for exactly what to (re)load for an initial creation versus an existing version.

## Resolving the base version

Before reading `guidance/paper-guide`, loading a document, or touching any proposal file, call the engine's `STATUS` operation once to get the deterministic ground truth of `proposals/` — never eyeball the directory listing yourself:

```json
{ "operation": "STATUS" }
```

or, if you already have a candidate base file in mind:

```json
{ "operation": "STATUS", "sourceFilename": "<candidate-filename>.md" }
```

`STATUS` is read-only, keyless, makes no model call, and needs no `ANTHROPIC_API_KEY`. It reports `managedRevisions` (every recognized managed revision, each with `lineage`/`revisionNumber`/`isLatest`), `latest`, `multipleActive`/`candidates` (when the latest is tied across lineages), `nonManagedFiles`, and — only when `sourceFilename` was supplied — a deterministic `sourceClassification` of `LATEST`, `OLDER_MANAGED` (with `newerRevisionNumbers`), `UNMANAGED`, or `NOT_FOUND`. See [usage examples](references/usage.md) for a worked transcript. Run exactly the decision tree below against that response.

### Backups: agent-performed, user-confirmed, never the engine's job

Whenever a branch below says "move," the destination is always `backup/proposals/<timestamp>/` at the **repository root** — a fresh timestamped subdirectory per reconciliation (e.g. `backup/proposals/2026-08-01T12-30-00Z/`). You perform that move yourself with a plain file-move (Bash `mv`), and only after the user explicitly confirms — the engine has no operation that moves, backs up, or deletes proposal files, and `STATUS` itself performs no mutation. If a moved managed revision has per-revision sidecars (`.proposal-deliberation/state/<filename>.json`, `.proposal-deliberation/receipts/<filename>.json`), move those alongside its `.md` too, so the backup stays internally consistent — none exist for a plain unmanaged file, but never leave a sidecar behind for a managed one.

**Verify the move before you continue — this step is not optional.** Run the consistency audit against the project root and require `status: "PASS"`. `STATUS` will not tell you the move went wrong: leave a sidecar behind and it still answers `ok` with the new latest, as if nothing happened. Only the audit names the damage, as `ORPHAN_STATE` / `ORPHAN_RECEIPTS`. A reconciliation that ends at `STATUS` leaves orphans that surface much later, when whatever trips over them has lost all connection to the move that caused them.

Restoring is the same procedure in reverse — move the `.md` and both sidecars back, then audit again. A revision and its sidecars return byte-identical; nothing is ever re-deliberated to undo a reconciliation.

### The decision tree

1. **You have a path in mind, and `sourceClassification` is `LATEST`.** Proceed — it is already the latest managed revision; work on it directly.
2. **You have a path in mind, and `sourceClassification` is `OLDER_MANAGED`.** `newerRevisionNumbers` lists the revision(s) that exist above it in the same lineage (`r(N+1)…rM`). Ask the user: move those newer revisions to `backup/proposals/<timestamp>/` and resume work from `rN` (the path you had in mind), or keep working on the actual current latest (`rM`) instead? On "move," relocate exactly `r(N+1)…rM` (and their sidecars) and treat `rN` as the latest from now on. On "keep," drop the older path and continue on the real latest.
3. **You have a path in mind, and it does not match the managed format (`sourceClassification` is `UNMANAGED`).** Ask the user: move the current managed revision(s) to `backup/proposals/<timestamp>/` and START FRESH, using that file's content as the new v1 base — or ADOPT it as v1 directly with `ADOPT_INITIAL_REVISION` (`sourceFilename` = that file)? Adoption preserves the file's real structure and is the better choice for an already-rich, developed document, versus re-rendering a generic seed from scratch. Either choice is the user's call — never default silently. Adopt through the engine, never by hand: `ADOPT_INITIAL_REVISION` runs the same canonical-form gate and pre-publish validation `CREATE_INITIAL_REVISION` runs, and writes the same committed state and receipt, under `research-concept-<slug of its first # title>-r01.md`. A marker prepended and a file renamed by hand gets none of that — no state, no receipt (the consistency audit reports `MISSING_MANIFEST`) and no validation. The engine leaves the source file in place; moving it to a backup is your confirmed step, as below. See [usage](references/usage.md#adopting-an-existing-document-as-v1).

   **An old hand-adopted v1** (the marker added by hand, no receipt; the audit reports `MISSING_MANIFEST` for it) keeps reading exactly as before; nothing invalidates it. To give it its record, run `ADOPT_INITIAL_REVISION` with `sourceFilename` set to that revision itself: after the same validation it writes the committed state and receipt and leaves the bytes untouched. A revision that already has a receipt is refused `ADOPTION_ALREADY_RECORDED`, never re-recorded.
4. **No path in mind, and a latest managed revision exists (`latest` is non-null, `multipleActive: false`).** Work on `latest` directly.
5. **No path in mind, zero managed revisions, and `proposals/` is otherwise empty (`nonManagedFiles: []`).** A pure initial creation — ask the user for their idea and proceed to `CREATE_INITIAL_REVISION`. **Their idea needs at least two sentences.** The engine takes the document's title from the first and its section heading from the second, each without its terminal `.`, `!` or `?`, and then writes the whole idea verbatim as that section's body (the headings are labels; the body keeps your full text); with no second sentence both come out byte-identical, every later attempt to name a place in that document is ambiguous, and the revision can never be edited. `CREATE_INITIAL_REVISION` refuses that outright — `code: 'INITIAL_IDEA_SINGLE_SENTENCE'`, nothing written. A sentence ends with `.`, `!` or `?`; a line break is not a sentence boundary.
6. **No path in mind, zero managed revisions, and exactly one non-managed file exists.** Ask the user: "is `<that file>` your initial idea/base for this proposal?" — do not assume it.
7. **No path in mind, zero managed revisions, and several non-managed files exist.** Ask the user which one (by name or path) to start from — never guess among them.

If `multipleActive` is `true` (a tied latest across lineages), stop and ask the user for the exact `sourceFilename` before doing anything else in any branch above — never treat one of `candidates` as authoritative on your own.

### Context-loading rule

- **Initial case only — creating v1 (decision tree branches 3's "START FRESH" choice, 5, 6, 7):** load `guidance/paper-guide` once, exactly as `CREATE_INITIAL_REVISION` itself already does internally. This ingest exists only to seed a brand-new proposal. The engine reads `<folder>/<folder>.md` files first, then flat `*.md` files, and stops at 4000 bytes in total by default: a guide document crossing that limit is cut and later ones are not read. The result's `sourceWindow` lists every document with its `status` (`loaded`, `truncated`, `not-loaded`), a `SOURCE_WINDOW_TRUNCATED` warning names what was cut, and `sourceWindowBytes` (1 to 262144) widens the window for that creation. See [usage](references/usage.md#the-source-window).
- **Any existing version (`r ≥ 1`) — branches 1, 2, 3's "ADOPT" choice, and 4:** load the latest version's document plus a brief general objective/framing for the deliberation. **Never** reload the paper-guide for an existing version — that ingest is spent only once, at true v1 creation.

## Deliberate, then decide

Deliberation state (turns, what has been discussed, what the user has approved) lives in **this conversation** — not in the engine. You hold the thread.

The engine does accept a `CHAT_DELIBERATION` operation, and a `CLOSE_DELIBERATION` to end it. **Do not use them.** They are not deprecated and not broken — their state is a map in memory that dies with the process, so they never persist a conversation or leak one deliberation into another. They are simply not this skill's way of working: deliberation belongs in this conversation, where the reasoning stays visible to the user instead of becoming an engine turn they cannot read. A revision you publish while a conversation is open carries that conversation's latest conclusion into the edit as advisory evidence, which is exactly the coupling this skill avoids by holding the thread itself.

- Discuss each proposed change against the rigor criteria above. Refute what does not hold up; refine what is close; accept explicitly what is sound.
- Keep a running tally, in your own working notes, of every change the user has explicitly approved but not yet applied to the document.
- Once the accumulated approved-but-unapplied set grows large — roughly more than 4 independent sections, or more than 40% of the document — say so and suggest materializing (applying) what has accumulated so far, before piling on more. This is advisory: never block or refuse further deliberation over it. (The engine restates the same advisory, computed from the document itself, in its own response once you apply a change — see below.)

## Applying an approved change

When the user approves one or more changes, you resolve them into `EditAction` decisions and hand them to the engine as `resolvedDecisions`. The engine never calls a model; it only validates and applies exactly what you give it.

### 0. Open ONE persistent `--serve` process for the whole deliberation

Before resolving anything, start a single long-lived process and keep it open for resolve, preview, accept, and every further version in this deliberation — one JSON request per line over the same stdin:

```bash
node skills/proposal-deliberation/cli.mjs --serve
```

The engine host itself cold-starts in well under a second (compiling its TS sources once via jiti), but that cost is paid **once per process**, not once per call. Resolving a locus, previewing, and accepting are three separate calls — send all three (and any later version's calls) down this SAME stdin instead of spawning a fresh `cli.mjs` invocation for each one; only the `acceptSuccessor` step strictly requires this (the acceptance token lives only in that process's memory), but doing it for every call is what actually amortizes the cold start across the whole deliberation.

### 1. Resolve the real target entry ID first

Every decision must name the *engine's own* resolved entry ID for its target — never a guessed, invented, or human-readable identifier. To learn it before building a decision, send a `RESOLVE_TARGET` line to the SAME `--serve` process you opened above (no mutation, no model call, no `ANTHROPIC_API_KEY`):

```json
{ "operation": "RESOLVE_TARGET", "sourceFilename": "<managed-filename>.md", "query": "<distinctive words from the target heading>" }
```

**Write the query as distinctive heading words, not as a sentence.** The resolver scores a heading by how many query words are words of its heading line, so a query is only as good as its rarest words. A query word matches a heading only when it equals one of the heading's own words, never part of one: `O1` matches `### O1. Objective` and not `### O10. Scope`, and `entropy` still reaches `Cross-entropy` because each part of a hyphenated word counts. A heading whose words are exactly the query's (ignoring its section label and stopwords) outranks one that merely contains them, so `Alignment loss` names `## Alignment loss`, not `## Alignment loss weighting`. Use the content words of the target's heading and nothing else: no punctuation (the query is truncated at the first `,;:.`, so `"Sección 3. Formulación…"` collapses to `"3"`), no section number, and keep accents exactly as the heading spells them (matching is accent-sensitive: `"normalizacion"` does not match `Normalización`). Stopwords are filtered out for you, but everything else you add is scored.

- ✅ `"Normalización términos adaptación"`
- ✅ `"## 5. Normalización de los términos de adaptación"` — level marks first: the heading spelled out, label and punctuation included
- ❌ `"Sección 5. Normalización de los términos de adaptación"` — after a section noun, punctuation truncates it to `"5"`

**Naming an outer section.** Open the query with the heading's level marks and only headings of that level are considered: `## Data` names the whole `## Data` section, subsections included, even when `### Synthetic data` carries the same word, which is how a line directly under `## Data` (a `**Dataset:**` label, say) becomes editable. A level-marked query is read as the heading spelled out, so its label and punctuation are harmless: `## 4. Baselines: comparison table` is a valid selector. Without level marks every level is considered, and a match nested inside another is no longer collapsed to the innermost section: a tie blocks and lists both.

which returns:

```json
{ "status": "resolved", "operation": "RESOLVE_TARGET", "entryId": "...", "blocked": false, "question": null }
```

`RESOLVE_TARGET` reuses the exact same resolver (`loadDocumentState` → `resolveSuccessorTarget` → `ambiguityGate`) that `CREATE_SUCCESSOR` itself uses internally, so the `entryId` it returns is guaranteed to match what `CREATE_SUCCESSOR` will resolve for the identical `sourceFilename`/query — there is no separate, divergent resolution path. If `blocked` is true the locus is ambiguous — **remove words, never add them** (and never guess from the menu). When a query is blocked, `question` and `candidates` list every candidate with its level marks and its real heading path (`### Methods › Setup`); name the one you meant by its own heading words, or by level marks for the outer one. Adding words to "narrow" the description is what caused the ambiguity: every extra word matches more headings. The blocked `question` names the terms that matched every candidate; drop exactly those and resolve again. If instead you get `SUCCESSOR_TARGET_NOT_FOUND`, no heading line matched at all — the query described the section's *content* rather than its *title*, so name the heading. A successor locus is never resolved from body text, precisely so a near-miss cannot silently hand you the wrong section. Do this once per independent locus you intend to touch. To resolve more than one locus in a single call, send `queries` (an array of `{ "query": "..." }`) instead of `query`; the response returns one `{ query, entryId, blocked, question }` result per entry in the same order. See [usage examples](references/usage.md) for a worked recipe.

### 2. Build one `EditAction` per resolved locus

| Kind | Fields | Notes |
| --- | --- | --- |
| `replace` | `targetEntryId`, `replacementText` | The default for a rewritten paragraph, definition, or block. |
| `insert` | `anchorEntryId`, `position` (`before`\|`after`\|`inside_start`\|`inside_end`), `content` | Adds new content at a resolved anchor. |
| `delete` | `targetEntryId`, `instructionEvidence`, `reason` | Removes the resolved target. |
| `move` / `copy` | `sourceEntryIds` (one entry), `destinationAnchorId`, `position`, `moveMode` (`LITERAL`\|`ADAPTIVE`), `removeSource`, `cleanupLevel`, `transformedContent`? | A relocation. |

For `move`/`copy`: the kind, source, destination, and position are whatever the user's own instruction asked for — you review and refute them, you do not invent them. A `LITERAL` relocation carries the source content byte-for-byte (omit `transformedContent`). An `ADAPTIVE` relocation (the moved/copied text must be reworded to fit its new context) requires you to supply that reworded text yourself in `transformedContent` — never leave it to the engine, and never fabricate wording you have no basis for.

**Never alter text you were not authorized to touch.** For every kind, everything outside the declared locus is left completely untouched — this is enforced by the engine, not by convention.

**Keep your replacement/inserted content well-formed Markdown, or the engine will reject it.** The candidate validator refuses a successor that fuses or malforms Markdown/display blocks (`successor-markdown-block-safety`). Concretely, when you write `replacementText`/`content`:
- **Preserve block-boundary blank lines.** End a block-scoped replacement with the same trailing blank-line separation the original block had, so it does not fuse with the following block (e.g. a section body that ends before the next `## ` heading keeps its terminating `\n\n`).
- **Display math is its own block.** Write a `$$ … $$` display equation on its own lines with blank lines around it — never inline inside a prose sentence — and keep every `$$` balanced and every LaTeX command well-formed. Inline or unbalanced display math is rejected.
- Patch only complete Markdown blocks; do not cut a replacement off mid-block.
- **Every ATX heading stands on its own line.** A `#`–`######` marker followed by a space anywhere else on a line is refused as `atx-heading-standalone`. A marker inside a backtick code span (`` `## Results` ``) is text, not a heading, and passes.
- **Label a section you want tracked downstream.** `proposal-implementation`'s `verify` reports which sections moved between two revisions, keyed by the label a heading starts with: a number (`## 3. Formulation`), a dotted number (`### 3.1 Kernel`) or an identifier (`### O1. Objective`), as defined once in `skills/_core/conventions/sections.json`. Keep a section's label unchanged across revisions; a heading with no label is reported as part of the labelled section around it.
If the engine returns `successor-markdown-block-safety` or `atx-heading-standalone`, the fix is a well-formed replacement (fix the spacing / make the equation a standalone block / put the heading on its own line), never a workaround. The preview runs the accept turn's own pre-publish validation, so either refusal arrives at the preview as `CANDIDATE_VALIDATION_FAILED`, before any acceptance token is issued, with `nextAction: "repair_candidate"` and one blocker naming the rule, its message and its repair step.

#### The canonical form: how this document spells mathematics

Every byte you send the engine — `replacementText`, `content`, `transformedContent` — obeys these. They are what makes the `.md` render, and the engine now blocks a candidate that breaks any of them (`mathCanonicalForm`).

1. **Inline math is `$…$`**, opened and closed on the same line. Never `\(…\)`.
2. **Display math is `$$` alone on its own line**, opening and closing, with a blank line before and after the block. Never `$$…$$` inside a prose line. Never `\[…\]`. (A LaTeX line break with spacing, `\\[1em]`, is not a delimiter and is fine.)
3. **Notation is LaTeX commands, never Unicode glyphs**: `\varepsilon` not `ε`, `\sum` not `∑`, `\leq` not `≤`, `\mathcal L` not `ℒ`, `\infty` not `∞`. Checked inside math delimiters, where notation lives; prose may be any Unicode it needs.
4. **Numbering is `\tag{N}`**; cite in the document's own prose form, `(Ec. N)`. A citation whose tag does not exist blocks the candidate.
5. **Chat rendering is a view, never a source.** See [Showing mathematics in chat](#showing-mathematics-in-chat) — Unicode belongs in what you say to the user, never in a byte the engine stores. Rule 3 enforces this: a leaked glyph fails the candidate.

#### Removing mathematics requires saying so

The preview returns a `mathDelta`: which mathematical atoms — display equations, inline math, `\tag` values, LaTeX macros, `(Ec. N)` citations — existed before and are gone after.

```json
"mathDelta": { "lost": [{ "id": "display:2a32c3fe", "kind": "display", "text": "x_{t+1}=A x_t" }], "added": [] }
```

**Read that list. It is the only thing standing between a rewritten section and mathematics that silently disappears from the paper.** Byte coverage guards what lies outside the locus; inside it, this is the guard.

To publish, echo the ids of every lost atom in `acknowledgedMathRemovals` on the accept call. Leave one out and the engine answers `MATH_REMOVALS_NOT_ACKNOWLEDGED` and publishes nothing.

```json
{ "operation": "CREATE_SUCCESSOR", "…": "…", "acceptSuccessor": true, "successorAcceptanceToken": "…", "acknowledgedMathRemovals": ["display:2a32c3fe"] }
```

Editing an equation counts as removing its previous form — that is deliberate. Before you acknowledge anything, tell the user in plain language what is leaving the document and confirm it was part of what they approved. An acknowledgment you cannot justify from the deliberation is a defect, not a formality.

### 3. Call the engine: `CREATE_SUCCESSOR` + `resolvedDecisions`

Send this as the next line on the SAME `--serve` stdin you resolved the entry ID on in step 1:

```json
{
  "operation": "CREATE_SUCCESSOR",
  "sourceFilename": "<managed-filename>.md",
  "instruction": "<the user's request, in their own words>",
  "selectedEntryId": "<the same query used to resolve the entry ID above>",
  "resolvedDecisions": [
    { "kind": "replace", "targetEntryId": "<resolved entry ID>", "replacementText": "<new text>" }
  ]
}
```

For more than one independent locus in the same version, use `selectedEntryIds` (plural — one query per entry) instead of `selectedEntryId`, and supply one decision per resolved locus in `resolvedDecisions`.

No `ANTHROPIC_API_KEY` and no model configuration are ever required — this call never makes a network or model call. There is no separate `PROPOSAL_DELIBERATION_MODEL` setting anymore, and no per-call cost budget to manage; the environment is only `PROPOSAL_DELIBERATION_PROJECT_ROOT` (defaults to cwd) and `PROPOSAL_DELIBERATION_SESSION_ID`.

**The instruction cap: 65,536 characters.** Every operation's `instruction` — for `CREATE_INITIAL_REVISION`, the whole idea — is at most 65,536 characters (JavaScript string length, UTF-16 code units). A longer one is refused before anything runs, `status: "blocked"`, `code: "INSTRUCTION_TOO_LONG"`, `nextAction: "shorten_instruction"`, nothing written. The successor preview and the first revision's result carry `instructionBudget: { "limit": 65536, "used": <n>, "remaining": <65536 - n> }`, so you can see the room left before you grow an instruction further.

### 4. Preview, then accept, in the same session

The call above only **previews**: it returns `status: "awaiting_acceptance"`, an `acceptanceToken`, the would-be `targetFilename`, and (once approved decisions are large enough) a non-blocking `growthAdvisory`. Nothing is written yet.

To publish, send the identical request with `acceptSuccessor: true` and `successorAcceptanceToken: "<the returned acceptanceToken>"` as the next line on the SAME `--serve` stdin — the acceptance token is short-lived, single-use, and held in that process's memory only. So by this point one `--serve` process (opened in step 0) has already carried the resolve line, the preview line, and now the accept line:

```
node skills/proposal-deliberation/cli.mjs --serve
```

```
{"operation":"RESOLVE_TARGET", ...}
{"operation":"CREATE_SUCCESSOR", ...}
{"operation":"CREATE_SUCCESSOR", ..., "acceptSuccessor":true, "successorAcceptanceToken":"<from the preview line>"}
```

Never split resolve/preview/accept across separate one-shot invocations of `cli.mjs` — a fresh process has no memory of the previous one's acceptance token (and pays a fresh cold start for nothing). Keep the same `--serve` process open for the rest of the deliberation, too: resolving and applying a later version reuses it exactly the same way.

**Record why, and who decided.** The receipt keeps an `instructionHash`, not the instruction, so on its own it cannot say why the revision exists. Add `"rationale": "<why, at most 2000 characters>"` and `"decider": "agent"` or `"human"` to the request and the successor's receipt (`.proposal-deliberation/receipts/<file>.json`) records both verbatim beside the hash. Both are optional: a receipt without them, including every receipt written before 0.14.0, validates exactly as before. Send them on the accept line (sending them on the preview too is harmless); `decider` states who took the decision — `human` when the user accepted the change, `agent` when you decided it yourself — and never what you would have liked it to be. A blank or over-long `rationale` or any other `decider` is refused `DECISION_RECORD_INVALID` before anything runs, and either field on an operation other than `CREATE_SUCCESSOR` is refused `DECISION_RECORD_UNSUPPORTED`.

A successful accept returns `status: "published"`, the new managed filename and hash, a `receiptId`, `manifestStatus: "COMMITTED"`, and `auditStatus`/`selfAuditStatus: "PASS"`. Treat anything else — a different status, a failed audit, or a `recoveryStatus` other than `not_required` — as incomplete; do not tell the user the edit is done.

### 5. One version per homogeneous batch

In-place edits (`replace`/`insert`/`delete`) publish as one successor version. A relocation (`move`/`copy`) publishes as a separate version. A batch that mixes both kinds still completes in one accept call, but produces two published versions in sequence — the response's `versions` array reports both.

### 6. The engine is still your safety net

The engine independently re-resolves every locus at call time and validates what you supplied against it — it does not trust you blindly, because you can still err (name the wrong section, alter text outside your authorization, or send a malformed decision). Treat a rejection as a real defect in your own resolution, not an engine bug:

- `WRONG_TARGET_ENTRY_ID` — your decision's target does not match what the engine resolved for that locus. Re-resolve (step 1) and retry.
- `ALTERED_REPLACEMENT_TEXT` — for an exact-block fidelity edit, your replacement text does not match the block the user asked to preserve byte-for-byte. Copy it exactly.
- `MALFORMED_DECISION_SHAPE` / `UNEXPECTED_DECISION_FIELD` / `WRONG_ACTION_KIND` — your decision's shape or kind does not match the table above.
- `NO_MATCHING_DECISION` / `AMBIGUOUS_MATCHING_DECISIONS` — every resolved locus needs exactly one decision; none or more than one was supplied for it.
- `SOURCE_EQUALS_DESTINATION` / `HIERARCHY_CYCLE_DESTINATION_DESCENDANT` / `NO_OP_PLAN` — the relocation or replacement you described is structurally impossible (self-referential, nests inside itself, or changes nothing). Ask the user to clarify instead of forcing it through.

None of this is negotiable and none of it is something you should work around — if the engine rejects a decision, the fix is a better resolution or a clarified instruction, never a different request shape designed to slip past validation.

## Non-negotiables

- Never fabricate mathematics, notation, citations, or numeric results.
- The same mathematics, variables, and structure must carry across versions unchanged unless the user explicitly approved changing them. Wording and explanation *may* change as long as the underlying notion is preserved — rephrasing is not the same as altering meaning, and you should say so when you rephrase.
- Untouched content is byte-identical across a successor version — this is a guarantee the engine enforces structurally, not a courtesy.
- Never invent an entry ID, offset, hash, patch, or receipt field. Resolve, don't guess.

## Other engine operations

| Operation | Use it for |
| --- | --- |
| `STATUS` | Read-only, keyless inventory of `proposals/` — managed revisions, the latest, tie/ambiguity detection, non-managed files, and (with `sourceFilename`) a deterministic classification of one candidate path. Never mutates. Use it at the start of every deliberation — see [Resolving the base version](#resolving-the-base-version). |
| `ADOPT_INITIAL_REVISION` | Makes an existing document v1 (`sourceFilename` names an unmanaged `.md` in `proposals/`), or records the missing state and receipt of an old hand-adopted v1 (`sourceFilename` names that revision). Same gate, state and receipt as `CREATE_INITIAL_REVISION`; accepts `--dry-run`. See [usage](references/usage.md#adopting-an-existing-document-as-v1). |
| `CREATE_INITIAL_REVISION` | Creates the first managed proposal (v1) from the user's idea plus the paper-guide. Only when no managed proposal exists yet; never automatic, never overwrites or duplicates one. A success leaves a permanent creation lock (`.proposal-deliberation/locks/initial-revision.lock`), so preview it first with `--dry-run` (or `"dryRun": true`): every check and the composed `markdown`, no lock, no write. See [usage](references/usage.md#dry-run-first-see-v1-before-it-exists). |
| `WITHDRAW_REVISION` | Safely withdraws one eligible managed revision, preserving an audited recovery copy. Not content deletion. |
| `RESTORE_WITHDRAWN_REVISION` | Restores a previously withdrawn managed revision from its audited recovery copy. |

`STATUS` is additive and read-only, handled directly by the CLI host (like `RESOLVE_TARGET`); the others are deterministic and were never model-backed. See [usage examples](references/usage.md) for request shapes.

## Limits

- The paper-guide reference and lite-evidence ingestion discipline used for sourcing new *papers* is a separate concern from this skill; do not import that discipline here or vice versa.
- `CREATE_INITIAL_REVISION` and `ADOPT_INITIAL_REVISION` are the only ways to create a managed proposal, and only when none exists yet.
- An `instruction` longer than 65,536 characters is refused with `INSTRUCTION_TOO_LONG` on every operation; see [the instruction cap](#3-call-the-engine-create_successor--resolveddecisions).
- If more than one active managed revision resolves, the engine reports `MULTIPLE_ACTIVE_REVISIONS` with the full candidate list — never silently pick one; ask the user for the exact `sourceFilename`.
- A multi-locus `CREATE_SUCCESSOR` batch may mix `replace`/`insert`/`delete`/`move`/`copy` freely; a conceptual (non-literal, reasoning-bound) revision beyond a single resolved replacement is not supported through this ambient path — treat it as a deliberation to resolve into concrete, resolvable edits first.
- Use only `node skills/proposal-deliberation/cli.mjs` for execution. Do not modify engine infrastructure, tests, or this skill during normal proposal work.
- Do not expose or ask the user to supply internal patch, offset, hash, or publication mechanics — those are entirely the engine's concern; only the resolved entry ID (step 1 above) ever crosses the boundary, and only because the engine itself produced it.

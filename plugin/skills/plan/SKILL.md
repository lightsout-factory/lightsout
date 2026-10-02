---
name: plan
description: Produce a rigorous, implementation-ready plan for a feature — one a fresh-context agent can implement without guessing. Explores the codebase, interviews you to drain what you know, drafts the plan, grills it for edge cases, and grades it to A. Use when the user wants to plan a feature, write an implementation plan, or get a plan graded before implementing. Input is a feature description or a rough-notes file path. Output feeds the `implement` skill.
allowed-tools: Bash, Read, Write, Edit, Grep, Glob, Task, WebSearch, WebFetch
---

# lightsout: plan

**This skill is the interactive conductor, not the engine.** All determinism —
fact verification, the draft↔structural-lint loop, grading — lives in the
`lightsout plan …` subcommands as deterministic code. This skill only conducts
the human dialogue the engine cannot (Elicitation, Grill, gap resolution) and
relays typed results. **Do not add gates, retries, caps, or contract parsing
here.** The one branch you make is reading the typed `passed` verdict from
`grade.json`.

Resolve the plugin root once from this loaded skill's absolute path: it is two
directories above this `SKILL.md`. In Claude Code, `${CLAUDE_PLUGIN_ROOT}` may
provide the same path; do not assume that variable exists in Codex skill shell
calls. Use the resolved absolute path wherever `<plugin-root>` appears below.
Confirm `<plugin-root>/dist/cli.mjs` exists; otherwise stop and tell the user to
reinstall the plugin or run `pnpm bundle`.

## Shaping rules

**Read `<plugin-root>/skills/plan/shaping-rules.md` before step 0, and follow
it throughout.** It is the one copy of the rules this skill shares with
`brainstorm` and `auto-plan`: how to recommend a design, the design check, the
escalation bar that decides which questions reach the user, how to flag a
settled decision you believe is weak, and the Question format. Every question
this skill puts to the user — an Elicitation batch, an Approaches fork, a Grill
escalation, a Dedup finding, a Converge gap — clears that bar and uses that
format.

What is this skill's own:

- **A question that clears the escalation bar goes to the user.** One below it
  you answer yourself, record as an assumption, and list in the assumption
  digest (step 5). The alignment checkpoint (step 2) narrows this: until the
  user confirms it, a question whose answer depends on the goal or the design
  direction counts as clearing the bar, because neither is settled yet. A
  best-practice question is still yours to answer, before the checkpoint or
  after.
- **The final response may carry at most 2 full-format questions.** Truly
  trivial yes/no items may share one combined block instead of getting a block
  each. Grill escalations are stricter: one question at a time, always.

## Settled decisions

**Settled means settled — never re-ask it.** Before putting any question to
the user — an Elicitation batch, an Approaches fork, a Grill escalation, a
Dedup finding, a Converge gap — check whether the answer is already on the
record. If it is, take the recorded answer, and do not surface the question.
The user sat through that decision once; asking again spends their attention
on work already done and invites them to contradict themselves.

By the time the plan is drafted, settled decisions live in three places, and
all three count:

| Where | Holds |
|---|---|
| `.lightsout/work-orders/<work-order>/plans/<plan-id>/brainstorm-decisions.json` | what was settled with the user in the brainstorm before this session |
| `.lightsout/work-orders/<work-order>/plans/<plan-id>/decisions.json` | what was settled earlier in this plan session |
| the drafted plan's `## Decision Log` | a rendering of the rows of both, composed by the engine — read a settled answer here, never write one |

**Record first, refresh, then edit the plan.** The engine composes the
`## Decision Log` from the two record files, so a row written into a plan file
by hand is overwritten the next time it runs. Every decision made after the
draft — a grill answer, a dedup resolution, a converge resolution, a veto — is
appended to `decisions.json` **first**, then the log is refreshed with:

```sh
node "<plugin-root>/dist/cli.mjs" plan sync-decisions --name <name>
```

Only then edit the plan content the answer changes — implementation detail,
acceptance rows, constraints. Never write a `Decision Log` row by hand. The
steps below call this **the sync command**.

**Name the phases a decision concerns.** For a phased plan, a row that
resolves a finding carries `"phases"` naming the finding's `phase` file, plus
any other phase file the answer changes. A revision row that repeats a
question names the phases its new answer concerns; the engine also covers the
phases the row it replaces named. A decision that names its phases lets the
next re-grade read those phases and the phases connected to them, not the
whole plan. The step 2 glossary says when to leave the field out.

A ticket's `## Decisions` lines are the same kind of record: outcomes the
user settled before shaping began. Elicitation harvests them into
`decisions.json` (step 2), and from then on this section governs them like
any other row. A ticket's acceptance criteria are **not** decisions — they
are floors, never ceilings, and a criterion's silence about a case decides
nothing.

A settled question is **dropped**, not answered again. Do not append a
`Decision Log` row for it and do not mirror one into `decisions.json` — the row it would
duplicate is already there. The one row a settled decision may gain is a flag,
under the shaping rules' `## Flagging a weak settled decision`. Where a step
distinguishes answering a question yourself from putting it to the user, a
settled question is neither; it never enters that routing at all.

**Re-open a settled decision only for a contradiction you can name in a
specific file and line.** A preference for a different approach is not a
contradiction, and neither is a later step wanting a different answer than an
earlier one gave. A re-opened decision is asked in the Question format, with
the contradicting `file:line` stated in the Context. A settled decision you
believe is weak, with no contradiction behind it, is not re-opened: flag it
once, under the shaping rules' `## Flagging a weak settled decision`.

**A re-opened decision keeps both records.** Record the corrected answer as a
**new** row in `decisions.json`, **repeating the original row's `question`
text verbatim**, with a rationale naming the `file:line` and saying which row
it supersedes. The repeated question text is what marks the supersession: the
engine's renderer marks every earlier row sharing that question as superseded
by the later one, so the corrected answer is the binding one while both rows
stay in the log. Run the sync command afterwards. Never edit
`brainstorm-decisions.json` — brainstorm owns it, and both rows belong in the
log.

**The user's latest explicit instruction outranks every record.** When what they
say now contradicts a settled row, follow them. Record the new answer as a **new**
row repeating the original row's `question` text verbatim, with a rationale
naming the instruction and saying which row it supersedes, then run the sync
command. This sits beside the `file:line` re-open rule above, not in place of it:
that rule is about what *you* may re-open on your own, and this one is about what
the user has already decided to change.

**On a ticket holding several plans, an earlier plan's records are context, not
this plan's settled rows.** Read them for what was built and why, and do not
harvest their rows into this plan's `decisions.json`. The ticket's own
`## Decisions` lines still bind every plan of the ticket until they are
explicitly revised. Where this plan's direction conflicts with what an earlier
plan settled, surface it to the user rather than deciding it quietly. A change to
a plan whose implementation is already finished belongs in **this** plan — never
in an edit to that earlier one.

**This narrows what gets asked, not how hard a step pushes.** Every question
that is not already settled is still raised and routed through the escalation
bar, at whatever intensity its step calls for. Dropping a settled question is
not a licence to drop a hard one.

## Steps

**0. Name the plan.** `<name>` is the plan's address — the work order's label, a
slash and the plan's id. Never invent a folder name and never rename one:
`lightsout work-order new` is the one thing that writes a work order's name, and
it writes it once.

**With no work order yet**, create one — with the ticket when the request traces
to one, and with the words you would have slugged when it does not:

```sh
node "<plugin-root>/dist/cli.mjs" work-order new --ticket <ref>
node "<plugin-root>/dist/cli.mjs" work-order new --title "<a few words>"
```

Take the label it prints on its last line. Behind `--ticket` the engine reads
that ticket's title from the tracker and summarises it itself; behind `--title`
the words are taken exactly as typed.

**With a work order**, read what it already holds first:

```sh
node "<plugin-root>/dist/cli.mjs" work-order show --name <work-order>
```

Then continue the lowest-numbered plan still at `planning`, unless the user says
this is a separate plan — in which case add one:

```sh
node "<plugin-root>/dist/cli.mjs" work-order add-plan --name <work-order> --slug <slug> [--title <title>]
```

and take the address it prints on its last line. What that command refuses, and
why, is the ticket-workflow skill's `### Adding a plan`. One question comes
first, in the Question format: in single-plan mode with plan 001 already there,
whether to switch the work order to multiple-plan mode.

When the request is a rough-notes
file path (given by the user, or a `/brainstorm` handoff), read it before
anything else; when it already lives under the plans directory, take `<name>`
from the path segments below that directory instead of deriving a new one. Also read
`.lightsout/work-orders/<work-order>/plans/<plan-id>/brainstorm-decisions.json` when it exists — its rows
are decisions already settled with the user. Absent → nothing changes; that is
the normal path for a plan that started from a direct request. This read is not
the only one: the file may arrive during step 1, because `plan verify-facts`
fetches the brainstorm the ticket carries. Step 2's `Honor the brainstorm
hand-off` bullet reads the folder again after that command has run rather than
trusting the answer here.

Once `<name>` is settled, establish the plan's own worktree as the very first
shell command:

```sh
node "<plugin-root>/dist/cli.mjs" plan workspace --name <name>
```

Read the absolute path it prints on its last line, and do every later step from
that directory — reading source, authoring `facts.json`, and every
`lightsout plan …` call. The plan folder already in this checkout is copied
into the tree, so the brainstorm files read above are there too; pass any
rough-notes path as an absolute one, since it lives in the checkout you started
from. A nonzero exit is the end of the session — report the sentence it printed
and stop, never carry on in the launching checkout. The command is safe to
re-run: a session already standing in the tree is answered the same path.

The tree is the work order's, read from the branch its record saves, so a later
plan continues in the tree its earlier plans used and is researched against the
implementation already on that branch. While a live implementation run holds that
tree, the command refuses and names the run: report its sentence and stop.

On a work order that carries a ticket, surface any discrepancy between the ticket
text and the user's current direction
per the ticket-workflow skill's `## Keeping the body true` — and never hold this
session up waiting on a ticket edit.

**1. Explore (in-context) + verify.** Explore the codebase yourself: read the
files the request touches, follow the integration points, and note real
signatures. For a feature spanning many packages/layers, optionally fan out
read-only Explore subagents for breadth — either way YOU author the facts, and
only from paths you actually confirmed by reading them. Author
`.lightsout/work-orders/<work-order>/plans/<plan-id>/facts.json`. Write this **exact** shape (the engine
hard-parses it):
```json
{
  "request": "<the feature request>",
  "areas": [
    {
      "area": "<what this area covers>",
      "affectedPackages": ["<repo-relative package dir>"],
      "filesToModify": [{ "path": "<repo-relative>", "role": "<one line>" }],
      "patternsToMirror": [{ "path": "<repo-relative>", "takeaway": "<what to take>" }],
      "integrationPoints": [{ "name": "<symbol>", "signature": "<real signature>", "at": "<file:line>" }],
      "scripts": [{ "key": "<package.json script key>", "command": "<what it runs>" }],
      "namingConvention": "<one line>"
    }
  ]
}
```
Then run:
```sh
node "<plugin-root>/dist/cli.mjs" plan verify-facts --name <name> [--notes "<path>"]
```
It also fetches this plan's own brainstorm from the ticket —
`brainstorm-notes.md`, plus `brainstorm-decisions.json` when that brainstorm
settled anything, so its absence is ordinary rather than a fault — into
`.lightsout/work-orders/<work-order>/plans/<plan-id>/` before it reads anything, so a fresh worktree has
them without the folder having travelled.

Pass `--notes` when the request came from a rough-notes file — the engine
freezes a copy at `.lightsout/work-orders/<work-order>/plans/<plan-id>/brainstorm-notes.md` as the plan's first
artifact. Write-once: an existing snapshot is never overwritten, so re-running
verify-facts never clobbers it (a `/brainstorm`-authored brainstorm-notes.md is already
home — whether it was written here or just fetched from the ticket — and is
simply kept).
It deterministically checks every claimed path/script on disk and stamps the
verification into facts.json. Relay the summary; fix any genuinely wrong path
in facts.json and re-run verify-facts, and carry remaining missing-path
warnings into Elicitation.
- While exploring, deliberately check each settled brainstorm decision against
  the code you are reading. The value of the hand-off is that the plan trusts
  these rows without asking, and trust that is never verified is a guess. Note
  any conflict with the exact `file:line`.

**2. Elicitation** — drain the user's *conscious* knowledge (interactive):
- **Scope check first.** Before any detail question, judge the request's
  size: one plan, one phased plan, or several independent plans. When it is a
  genuine fork, ask in the Question format; when the request is several
  independent plans, say so, agree which to plan now, and record the split as
  a decisions row. This check aims the interview — the engine's `plan draft`
  still makes the single-versus-phased estimate on its own.
- **Collect global constraints.** Ask once, early, whether any project-wide
  rules bind this work (for example "no new dependencies", "the public API
  stays frozen"). Record each as its own decisions row whose `question`
  begins exactly `Global constraint:` — the drafted plan's Global
  Constraints section is built from these rows. None stated → no rows; the
  section will read "None". Constraints already recorded as brainstorm rows
  carry their own `Global constraint:` prefix and flow through untouched —
  ask only for rules not already settled.
- **Harvest the session first.** If the feature was discussed in this
  conversation before the skill was invoked, record each decision the user
  already made as a decisions row (`Source = "Elicitation"`) before asking
  anything. Those rows are settled — see [Settled decisions](#settled-decisions).
- **Harvest the ticket.** When the work traces to a ticket, record each line of
  its `## Decisions` as a decisions row (`Source = "Elicitation"`,
  `assumption: false`) before asking anything — those are settled. A line a brainstorm row
  revises — one whose `question` begins `Revises ticket decision:` and quotes
  that line — is not harvested: the brainstorm row is the user's later
  instruction and binds instead. Treat its `## Open questions` as part of the
  interview's agenda. A "no" the user settles to one of them is a decisions row
  like any other, and a rejected idea never becomes a new ticket.
- **Honor the brainstorm hand-off.** The rows in
  `brainstorm-decisions.json` are decisions already settled with the user, and
  [Settled decisions](#settled-decisions) governs them — never re-asked,
  re-opened only for a contradiction at a named `file:line`. Two things are
  particular to this step:
  - A row re-opened here is recorded with `source: "Elicitation"`. This
    matters most for `Global constraint:` rows, where the live row alone
    becomes a binding bullet.
  - Do not copy brainstorm rows into `decisions.json`; `plan draft` reads
    both files and merges them.
- Ask only what clears the escalation bar, in the Question format — at most 2
  full-format questions per message, the one whose answer moves the design most
  first. Elicitation drains what only the user knows; a best-practice question
  is answered, not asked. Resolve the decision tree branch by branch, reflect
  each answer back to converge on a shared understanding. Never ask what the
  codebase can answer — read it (or re-explore in-context, update facts.json,
  and re-run `plan verify-facts`) instead.
- Continue until the user is **tapped out and aligned** — their bound, not yours.
- **Alignment checkpoint.** Close by stating back, in plain words: the goal, the
  design shape, and the kinds of implementation detail you will decide yourself
  from here (best practice only). The user's explicit confirmation licenses
  Grill's self-answer routing (step 5); without it, every grill question that
  depends on the goal or direction escalates to the user, while a best-practice
  question is still answered, never asked. A brainstorm hand-off does not stand
  in for this checkpoint: the plan reads the code after brainstorm ended and may
  surface things brainstorm could not have known, so the licence to self-answer
  is still earned here.
- Author `.lightsout/work-orders/<work-order>/plans/<plan-id>/decisions.json`. Write this **exact** shape
  (the engine hard-parses it; a wrong field name blocks drafting):
  ```json
  {
    "planName": "<name>",
    "decisions": [
      { "source": "Elicitation", "question": "<q>", "options": "<A / B>",
        "choice": "<chosen>", "rationale": "<one line>", "assumption": false },
      { "source": "Converge", "question": "<q>", "options": "<A / B>",
        "choice": "<chosen>", "rationale": "<one line>", "assumption": false,
        "phases": ["phase2-<slug>.md"] }
    ]
  }
  ```
  `source` is exactly `"Elicitation"` | `"Grill"` | `"Dedup"` | `"Converge"`;
  `options` is a string; `assumption` is a bool. Mark a choice made without user
  confirmation as an assumption. `phases` is optional: a list of the
  phase-file basenames the decision concerns. Leave it out when the decision
  reaches the whole plan, when its reach is not known, on rows written before
  the plan is drafted (phase files do not exist yet, so no Elicitation or
  Approaches row carries it), and on `Global constraint:` rows, which always
  reach the whole plan. Never write an empty list.

**3. Approaches** — settle the design shape before drafting (interactive,
conditional). Run this step only when the design shape is not already settled
— by the session discussion, the Elicitation answers, or a brainstorm decision
naming the chosen approach; [Settled decisions](#settled-decisions) is the
test. When it is settled, say so in one line ("Design shape settled during
Elicitation — skipping approaches", or "Approach settled during brainstorm —
skipping approaches") and move on — never skip silently. Present the genuinely
different approaches that survive the shaping rules' `## Recommending a design`,
in the Question format — as many as survive, with no target count. Context states
the design problem in everyday words, Question asks which to build, Options
gives each approach with its wins and costs, Recommendation names one by number
with the one-line why. When only one survives, there is no choice to ask about:
show it as a Design statement, under the shaping rules' `## Design statement`,
say in one line why the others fell, and confirm it matches what the user meant.
Record the chosen approach as a decisions row
(`Source = "Elicitation"`) before drafting.

**4. Draft.** Run:
```sh
node "<plugin-root>/dist/cli.mjs" plan draft --name <name>
```
Pass `--scope single|phased` only to override the engine's estimate. On
`facts error` → re-explore in-context, correct facts.json, re-run
`plan verify-facts`, then re-draft. On
remaining `structural issue(s)` → relay them. On success → note the written
`plan.md` path.

A phased draft runs in two stages: one agent authors `overview.md`, the engine
checks the phase breakdown it declares against both ceilings — the created-file
ceiling and the touched-file ceiling of 70 — and then one agent per declared
phase authors its `phase<N>-<slug>.md` concurrently. So `structural issue(s)` on
a phased plan may name the overview's **phase breakdown** rather than a phase
file: a phase that creates more files than one implementing agent may, or that
touches more files than one implementing agent can finish. The fix there is to
resplit the phases — edit the overview's `## Phases` table and its
`## Phase Declarations` to spread the created and touched files across more
phases — and re-run `plan draft`. A phase whose whole work is renaming may
instead be declared rename-only: a `## Renames` section in its phase file and
the `- **Renames only:** yes` bullet in its overview declaration. A phase whose
whole work is moving folders and files may instead be declared
move-folders-and-files: a `## Build Mode` section reading
`move-folders-and-files` in its phase file and the
`- **Moves folders and files only:** yes` bullet in its overview declaration. A
large folder move beside other work is resplit into a phase of its own for this.

**5. Grill** — push past conscious knowledge against the *drafted* plan
(interactive):
- **Design check first.** Before the edge-case stream, run the shaping rules'
  `## The design check` against the drafted plan. An objection you accept
  becomes a question like any other below — dropped if settled, routed through
  the bar, and folded into the plan the same way. One that would change a
  settled decision is flagged under `## Flagging a weak settled decision`
  instead.
- Thorough: generate the full stream of edge-case questions against the
  draft. Routing decides who *answers* each question, never whether it is
  raised; the settled check below is the one thing that removes a question,
  and it runs before routing. Explore the codebase instead of asking whenever
  possible.
- **Drop a question the record already answers.** Check each generated
  question against the brainstorm rows, `decisions.json` and the draft's
  Decision Log — see [Settled decisions](#settled-decisions) — before routing
  it. A settled question is neither escalated nor self-answered: it is
  dropped, with no new Decision Log row, because the answer is already logged.
  The rest of the stream is unaffected — this removes repeats, not rigour.
- **Route every question through the escalation bar before surfacing it.** One
  that clears the bar is escalated. One below it is self-answered — subject to
  the alignment checkpoint, as [Shaping rules](#shaping-rules) says. A question
  you are unsure about is self-answered and listed, as the shaping rules say.
- **Self-answered** → append the row to `decisions.json` with
  `"source": "Grill"`, `"assumption": true` and a rationale ending in
  `(self-answered)`, run the sync command, then fold the answer into `plan.md`
  via Edit. Do not surface it live.
- **Escalated** → **one question at a time**, in the Question format (one
  full labeled block per message — never two), the one whose answer moves the
  plan most first. After each answer, append the
  `decisions.json` row with `"source": "Grill"`, run the sync command, and
  **immediately fold the answer into `plan.md` via Edit**. Do not batch edits
  to the end.
- On a phased plan, either kind of Grill row carries `"phases"` naming the
  phase files the answer changes, and a row that re-asks a question names the
  phases its new answer concerns — see **Name the phases a decision
  concerns** under [Settled decisions](#settled-decisions).
- **Stop rule.** Stop when one complete pass over every plan file produces no
  question whose answer would change the plan; a second pass that only
  re-treads settled ground is the signal. Say the grill is done, and that it
  goes on if the user wants more. The user may also stop it at any point.
- **The grill also interrogates the ledger.** With `plan.contract` on, the
  plan carries an `## Acceptance Tests` table and a `## Prose Files` list, and
  three questions belong in the stream like any other: an acceptance criterion
  with no row, a row whose named test could not fail if the feature were never
  built, and a prose file that a test could have stated after all. Each finding
  lands where it belongs — a `decisions.json` row followed by the sync
  command, or a new ledger row.
- **Assumption digest.** When the grill stops, list every self-answered
  question with its chosen answer. A veto re-opens that question as an
  escalation — fold the corrected answer into `plan.md` before moving on.

**6. Dedup Review** — resolve prior-art duplication (interactive). This is the
last shaping of the plan; after it the plan is complete and Grade only verifies.
Run:
```sh
node "<plugin-root>/dist/cli.mjs" plan dedup --name <name>
```
Read `.lightsout/work-orders/<work-order>/plans/<plan-id>/dedup.json`. Detection and judgment are the
subcommand's; you only conduct the review and apply the chosen edits.
- `findings` empty → nothing to review; go to Grade.
- A finding whose resolution the record already carries is **not surfaced** —
  see [Settled decisions](#settled-decisions). The subcommand re-detects an
  overlap every run, so a resolution chosen on an earlier pass comes back as a
  finding; apply the resolution already recorded and say in one line that it
  was settled, rather than asking again.
- `findings` present → route each remaining finding through the escalation
  bar. Whether to reuse, extend or extract existing code is ordinarily a
  best-practice call, so most findings fall below it: apply the judge's
  `recommendation` — or a better resolution, when you can name why — and list
  each one, in plain words, in a short summary of what was applied. A finding
  that clears the bar — one whose resolution changes what the user sees, or
  that the user must weigh — goes to the user in the Question format (at most 2
  per message): **Context** says in plain words what the plan wants to build
  and what already exists that overlaps — never bare symbol names; **Question**
  asks which to pick; **Options** summarizes the resolutions to choose between;
  **Recommendation** is the judge's `recommendation` in plain words, unless you
  recommend otherwise and say why. A veto of an applied resolution re-opens it
  the same way. Append one
  `decisions.json` row with `"source": "Dedup"` per resolution — on a phased
  plan with `"phases"` naming the finding's `phase` file, plus any other phase
  file the resolution changes — and run the sync command once, then apply each
  chosen resolution to `plan.md` via Edit:
  - **reuse** → drop the Files-to-Create entry; wire the plan's usage to the
    existing symbol.
  - **extend** → add a Files-to-Modify entry for the existing symbol.
  - **extract** → add the shared file to Files-to-Create at `suggestedLocation`,
    plus a Files-to-Modify entry per `migrateCallers`.
  - **defer** → leave the entry; record the accepted duplication in `## Prior Art`
    (logged debt).
  - **distinct** → record the justification in `## Prior Art`.
- Each finding carries the `phase` it was planned in — the plan file's
  basename. Apply the resolution to **that** file, not to `plan.md`.
- `"complete": false` means a judge failed or hit the rate-limit wall. The
  findings present are real, but the scan is partial — resolve them, then
  re-run `plan dedup` before moving on.

**7. Grade + converge.** Run:
```sh
node "<plugin-root>/dist/cli.mjs" plan grade --name <name>
```
Read `.lightsout/work-orders/<work-order>/plans/<plan-id>/grade.json`:
- `"passed": true` **and** `"complete": true` → go to handoff.
- `"passed": false` with `gaps` → work **only the blocking gaps**: the ones
  whose `outcome` is `needs-a-human` or `unjudged`. A grader's label is
  evidence, not authority: route each through the escalation bar. One below it
  you resolve yourself, as an assumption, and list in plain words in a short
  summary of what was resolved, where a veto re-opens it. One that clears it
  goes in the Question format (at most 2 per message, recommended-first),
  **grouped by the gap's `phase`**. Resolve each by appending a `decisions.json`
  row with `"source": "Converge"` — on a phased plan with `"phases"` naming the
  gap's `phase` file, plus any other phase file the answer changes — running the
  sync command, then **editing the plan file the gap's `phase` names** in place
  via Edit — `plan.md` for a single plan, that `phase<N>-<slug>.md` for a phased
  one. Then re-run `plan grade`. Repeat until `passed` or the user calls it.
  **Do NOT re-run `plan draft`** — a re-draft regenerates the plan files and
  would clobber the Grill edits already folded in.
- A blocking gap whose answer the record already carries is **not surfaced** —
  see [Settled decisions](#settled-decisions). A re-grade re-reads the plan
  from scratch and can raise a gap over something settled in Elicitation,
  Grill or Dedup. Resolve it from the recorded answer, note in one line that it
  was already settled and where, and re-grade.
- Everything else the pass found is still in `grade.json`, in full, for the user
  or a later agent to read. Nothing was dropped; it was weighed and found not to
  need them.
- Every pass — including one that did not finish — is also appended as one JSON
  line to `.lightsout/work-orders/<work-order>/plans/<plan-id>/grade-history.jsonl`. `grade.json` is still
  the latest pass and still the only file to branch on; the history is there for
  the user, or for an agent asked to look, to see how a plan's grade moved
  across re-grades and which finding kept coming back. Nothing reads it
  automatically.
- Every gap carries an `outcome` saying who has to settle it:
  - `needs-a-human` — a person has to decide this one. These are the questions.
  - `agent-can-decide` — the implementing agent can settle it on its own, and
    `agentDecision` says what it would decide. Not a question.
  - `already-answered` — the answer is already in the plan or the code, and
    `answerAt` says where. Not a question.
  - `unjudged` — nobody weighed this one, so it blocks until someone does.
- **An `unjudged` gap is a different question from a `needs-a-human` one, and
  must not be dressed as the same thing.** It is never silently dropped. Below
  the bar, weigh it yourself, answer it into the plan, and list it in the
  summary as one nobody had weighed. When it clears the bar, surface it in the
  Question format like any other blocking gap — and in the same block, say
  plainly that it blocks because nobody weighed it, not because the plan is
  thin, and quote its `unjudgedReason`. Say that re-grading will **not** retry
  that judge: a re-grade re-runs every reader and comes back with a fresh set of
  findings, so this exact one may simply not reappear, and there is no way to
  re-judge a single finding. Leave the choice with the user: answer it into the
  plan, or let it go. Do **not** recommend a re-grade as the remedy — it reads
  like a retry and is not one.
- Every gap also carries the `lens` that found it (`surface`, `wiring`,
  `decisions`) — three differently-briefed checkers read every phase, so two
  gaps with the same text and different lenses are two lenses agreeing, not
  noise.
- While resolving, re-check a single phase you just edited with
  `lightsout plan grade --name <name> --phase <n>` — three checkers and about
  three minutes instead of a full pass. The final grade before handoff is
  **always** a full run with no `--phase`.
- **A grade whose `"complete"` is false, or whose `phasesChecked` does not list
  every phase file in the plan folder, is not a clean bill whatever its
  verdict.** Its gaps are real and worth fixing, but the unlisted phases were
  not looked at — say so to the user and re-grade once the fixes are in.
  (`overview.md` is deliberately never gap-checked and never appears in
  `phasesChecked`; it is checked deterministically instead.)
- **A pass whose `incompleteReason` names blocking structural findings ran no
  semantic reader at all.** Its `gaps` list is empty because nobody looked, not
  because the plan is clean. Fix the structural findings and re-grade before
  reading anything into it.
- `scope` says how far the pass reached. Only a `full` pass can be `passed`; a
  `focused` pass is a repair check over the edited phases and the phases they
  reach, and is always `"complete": false`. The engine chooses the scope itself
  and runs the full review automatically once a focused pass clears — there is
  no flag to pass and nothing extra to run.
- A blocking gap carrying a `findingId` is a finding the plan has seen before.
  Its record lives in `.lightsout/work-orders/<work-order>/plans/<plan-id>/grade-memory.json`, which the
  engine owns: **never edit it**, and never treat a finding's absence from a
  later pass as it being resolved. A record closes only when the plan states the
  answer and the engine's re-verification judge cites where.
- When a re-grade reports that a recorded passing full review still covers the
  current inputs, nothing was re-run and that grade is current. Deleting
  `grade-memory.json` forces a new baseline.
- `structural` findings present (rare) → apply each finding's exact `fix` to
  the plan file named by its `phase`, via Edit, then re-grade. A finding
  printed as `note` rather than `⚠` is **advisory**: information for you and
  the user, not work to do.
- With `plan.contract` on, `grade.json` also carries `weights` and
  `phasesLight`. Each plan file is weighed from its own counts — files created,
  packages touched, whether it has a pattern to mirror — and only a heavy file
  gets the reader fleet. A file named in `phasesLight` was graded by the
  deterministic lint and the ledger check alone, and its entry in `weights`
  says why. That is not a thinner grade of the same kind: it is the mechanical
  half, and the grill and the ledger are what carry the rest.
- Reading a typed field to decide what to display is not a gate. What blocks is
  decided in the engine and arrives as `passed`; you never recompute it.

**8. Handoff.** When the work traces to a ticket, take it to ready-to-implement
first, in this order:

```sh
node "<plugin-root>/dist/cli.mjs" plan publish --name <name>
node "<plugin-root>/dist/cli.mjs" ticket-state --ref <ticket> --planning-status planning-complete --tracker-status ready
```

Publish first, so the durable plan is on the ticket before anything claims the
ticket is ready to build. A successful publish is also what moves this plan from
`planning` to `ready` on the ticket's record. Between the two commands, drain the
ticket's `## Open questions` of every line the shaping answered. Then run
`ticket-state`. A nonzero exit from either command is a stop: report the exact
failure and do not print the handoff line below, because a ticket another machine
cannot recover is not ready for anyone. The rule behind the order is the
ticket-workflow skill's `### Publish when the ticket is ready to implement, not
at close` section.

On a multiple-plan work order, add one line to the handoff: it stays open
until the user files a ship request with `lightsout work-order request-ship`, and
the ticket-workflow skill's `### Ship requests` says what that request has to name.
Never file one yourself — the user decides the finish line.

With no ticket, skip both commands.

Then relay the final grade and:
```
Next: run the `implement` skill with .lightsout/work-orders/<work-order>/plans/<plan-id>
```
The same line works for both shapes — the engine reads the folder: an
`overview.md` runs every phase in order, otherwise the folder's `plan.md` runs
on its own. To run a single phase of a phased plan by itself, pass that phase
file instead: run the `implement` skill with
`.lightsout/work-orders/<work-order>/plans/<plan-id>/phase1-<slug>.md` as the plan and
`.lightsout/work-orders/<work-order>/plans/<plan-id>/overview.md` as its overview.

List any decisions left unresolved. The grade is
advisory — the `implement` skill runs whatever plan it is given.

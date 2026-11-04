# Designing a measurement of the governed composition

**Status: design only.** This document states what a measurement able to
discriminate the arms would need and what memkernel's published 0.5.0 run
shows. It preregisters, runs and budgets nothing, and it is not evidence for
or against any arm. Written 2026-11-03 for wiki-studio 0.8.1. Updated
2026-11-04, after it was filed as memkernel #90: §4's adoption row names the
recorded run, committed since; nothing else changed.

The comparison it works toward is the one in
[`docs/roadmap.md`](../../docs/roadmap.md#evidence): agent, model, task set
and memkernel retrieval held constant, with the curation workflow varied —
memkernel alone, memkernel with governed wiki-studio, files plus grep, and a
negative control. The measurement belongs to memkernel's lifecycle suite.
This document is the wiki-studio side's input to memkernel's decision; no
runner, task, checker, event schema or statistics code is written here.

## 1. What the published 0.5.0 run shows

### 1.1 Why every arm passed on `lc-wiki`

The published run included a `wiki_studio` arm on the five `lc-wiki` tasks.
All seven arms — `bare`, `placebo`, `protocol`, `claude_md`, `fs_grep`,
`memkernel` and `wiki_studio` — passed 25 of 25 trials, every pairwise effect
was +0.0, and the report's headline is "no gain claimed"
([`report-0.5.0.md:23`](https://github.com/gosha70/memkernel/blob/v0.5.0/eval/lifecycle-suite/report-0.5.0.md#L23),
results at
[87-108](https://github.com/gosha70/memkernel/blob/v0.5.0/eval/lifecycle-suite/report-0.5.0.md#L87-L108)).
Four properties of the task and the runner explain the ceiling:

1. Each `lc-wiki` task's exposure prompt tells the agent to record the
   decision as a page under `knowledge/wiki/`
   ([`task.json:14`](https://github.com/gosha70/memkernel/blob/v0.5.0/eval/lifecycle-suite/tasks/lc-wiki-backoff/task.json#L14)).
2. The runner copies the task's shared-artifact directory — that wiki — from
   the source session into the destination workspace for every arm
   ([`config.frozen.json:21`](https://github.com/gosha70/memkernel/blob/v0.5.0/eval/lifecycle-suite/arms/wiki_studio/config.frozen.json#L21)).
3. The evaluation prompt says where the wiki is
   ([`task.json:23`](https://github.com/gosha70/memkernel/blob/v0.5.0/eval/lifecycle-suite/tasks/lc-wiki-backoff/task.json#L23)).
4. The fixture wiki at
   [`tree/knowledge/wiki/`](https://github.com/gosha70/memkernel/tree/v0.5.0/eval/lifecycle-suite/tasks/lc-wiki-backoff/tree/knowledge/wiki)
   contains only `index.md`, so there is one fact, no competing page and no
   obsolete decision.

The wiki is therefore the carrier for every arm, `bare` included: any arm
that writes a file and reads it back passes. The `lc-wiki` group is at
ceiling, it supports no outcome difference between the arms, and it supports
no claim about the governed composition.

### 1.2 The two diagnostics, and what they do not show

The report records exactly two diagnostics for the `wiki_studio` arm
([`report-0.5.0.md:110-118`](https://github.com/gosha70/memkernel/blob/v0.5.0/eval/lifecycle-suite/report-0.5.0.md#L110-L118)):

- 0 of 177 Bash calls ran `wiki-studio ingest` or `wiki-studio query`; and
- 0 of 9 `Write`/`Edit` calls were under the wiki, against `fs_grep` at 52
  of 78 and `memkernel` at 38 of 63.

In the `lc-wiki` group the report records no outcome difference, and the
token totals do not support a cost difference (§1.3). The diagnostics are
not a gate finding, and this document does not read them as one. They do
not show that the `wiki_studio` arm stayed inside the gate: Bash can write
files without a `Write` or `Edit` call, and the receipts keep payload
hashes, not the commands that produced them or the gate records that should
accompany a landed page. A claim that an arm stayed inside the gate needs
the gate's own records checked for every page the arm lands. That check is
a requirement of the composition arm in §3.4; it is not something the
0.5.0 diagnostics provide, and no such claim is made here.

### 1.3 The token totals do not compare

The report gives `wiki_studio` 4,309,745 receipt tokens on 25 `lc-wiki`
trials. Each other arm's table total is between 18.6 and 20.4 million (about
19-20 million) over 100 trials in four groups
([`report-0.5.0.md:155-163`](https://github.com/gosha70/memkernel/blob/v0.5.0/eval/lifecycle-suite/report-0.5.0.md#L155-L163)).
That table is one total per arm, with no per-group breakdown, and different
task sets and trial counts sit inside the totals, so they do not compare and
no cost result follows. A per-group token table is a dependency on memkernel
(§5).

### 1.4 What follows

The `lc-wiki` group is a ceiling result. It tells us that this task set
cannot tell the arms apart, not that governance has no effect. The report
itself says the group is "limited mainly by its ceilings"
([`report-0.5.0.md:325-338`](https://github.com/gosha70/memkernel/blob/v0.5.0/eval/lifecycle-suite/report-0.5.0.md#L325-L338)).
The `wiki_studio` arm in that run was wiki-studio 0.4.1 through the CLI,
with no curator and no governed import; the composition the roadmap names is
a different, governed loop. The next measurement needs tasks on which the
negative control fails, and a composition arm whose correction arrives
through its own workflow.

## 2. A task set that can discriminate

### 2.1 Requirements

1. **A calibration that shows `bare` fails, before any measured run.** Run
   the whole set with the negative control and with an informed reference
   (the corrected rule supplied to a model outside the arm). A task where
   `bare` reaches the informed answer is at ceiling and must be rewritten or
   removed; a task the informed reference cannot answer is a broken prompt
   and must be fixed. The calibrated set and the calibration result are
   frozen before the measured run. Calibration qualifies the set; it is not
   exit evidence.
2. **An obsolete decision in every chain.** Session 0 records X. A correction
   event, delivered through the arm's own workflow between sessions, changes
   the project's rule to Y. Session 1 is evaluated. The checker has three
   outcomes: X is the obsolete answer and fails, Y is the informed answer and
   passes, anything else fails. The obsolete-answer rate — the share of
   trials answering X — is then executable from the frozen references and
   needs no judge. X and Y must be project-specific values that cannot be
   inferred from general knowledge, or `bare` can guess Y and the task
   measures nothing.
3. **The correction travels only through the arm's own workflow.** A file
   containing Y must not be copied into the second session for every arm. In
   particular, the shared-artifact rule that carries the wiki into every
   arm's destination workspace has to change: the exposure state may be
   shared, but the correction must be produced by the arm. For the
   composition arm, Y reaches the next session only through the export, the
   reviewed proposal, promotion, approval and governed import; for memkernel
   alone, through memkernel's own correction path; for files plus grep,
   through the curator's direct edit of the files; the negative control
   receives nothing. If the correction is handed to every arm, the group is
   back at the 0.5.0 ceiling.
4. **Competing pages.** The fixture wiki must contain at least one other page
   on the same topic — an obsolete page, a near-duplicate, or a distractor —
   so that reading one page is not enough. The obsolete text remains present
   in some artifact, so an arm that stops at the first match answers X. The
   answer requires selecting the current page or revision, which is what the
   wiki's index, `find`, `recall` and review state are for.

The session-1 prompt asks for the project's current rule. It does not name
the correction, the corrected value, or the page that carries it; the
preregistration records every prompt verbatim.

### 2.2 Task sketches

These are prose sketches, not task code. Each names the exposure prompt, the
correction, the evaluation prompt, the obsolete and informed references, and
the competing pages.

1. **Deploy window.** Session 0 records from a release briefing that deploys
   may go out on Friday after 17:00 UTC (X). After an incident, the correction
   changes the rule to no Friday deploys, with the window closing Thursday at
   15:00 UTC (Y). Session 1 asks whether a change ready on Thursday at 16:00
   UTC can be deployed that week. Obsolete reference:
   Thursday 16:00 or Friday is allowed; informed reference: the next window
   is the following Monday. Competing pages: the old release checklist that
   still lists Friday, and the incident page that describes the rollback.
2. **Session token lifetime.** Session 0 records that refresh tokens last 24
   hours (X). The correction changes the rule to 15-minute access tokens with
   rotating refresh tokens and re-authentication after 8 hours (Y). Session 1
   asks which lifetime applies to a partner integration that refreshes once
   per hour. Obsolete reference: 24 hours; informed reference: rotation every
   15 minutes with the 8-hour re-authentication boundary. Competing pages: an
   authentication overview carrying the old lifetime and a security advisory
   carrying the new one.
3. **Cache invalidation.** Session 0 records that the catalog cache expires
   after a 10-minute TTL (X). The correction changes the rule to purging on
   the `catalog.updated` event, with a one-hour TTL only as a backstop (Y).
   Session 1 asks what happens to the cached price immediately after an
   update. Obsolete reference: it is served for up to 10 minutes; informed
   reference: the update purges it at once. Competing pages: the performance
   guide that recommends the TTL and the postmortem that replaces it.
4. **Retry policy.** Session 0 records three immediate retries for any failed
   request (X). The correction changes the rule to exponential backoff with
   jitter, a 30-second cap, and retries only for idempotent calls (Y).
   Session 1 asks what a client should do after a 503 from a payment call.
   Obsolete reference: retry three times at once; informed reference: do not
   retry a non-idempotent payment call; back off only idempotent calls.
   Competing pages: the API guide with the immediate-retry example and the
   incident page that records the duplicate charges.
5. **Backup retention.** Session 0 records 30-day retention for the customer
   database (X). The correction changes the rule to 90 days for the customer
   database and 30 days for logs (Y). Session 1 asks how far back a deleted
   customer record can be restored. Obsolete reference: 30 days; informed
   reference: 90 days for the database, 30 for logs. Competing pages: the ops
   runbook with the old figure and the compliance page with the new one.
6. **Access review cadence.** Session 0 records quarterly access reviews
   (X). The correction changes the rule to monthly for production access and
   quarterly for everything else (Y). Session 1 asks when the next production
   access review is due after one was completed two weeks ago. Obsolete
   reference: next quarter; informed reference: next month. Competing pages:
   the security policy with the quarterly cadence and the audit finding that
   requires the monthly one.
7. **Feature flag cleanup.** Session 0 records that flags stay in the code for
   a year after rollout (X). The correction changes the rule to removal
   within 30 days of full rollout (Y). Session 1 asks what to do with a flag
   that reached full rollout 45 days ago. Obsolete reference: leave it until
   the year is up; informed reference: it is overdue for removal. Competing
   pages: the release playbook with the old rule and the ownership page with
   the new one.
8. **Invoice rounding.** Session 0 records that invoice amounts round half up
   (X). The correction changes the rule to banker's rounding to the nearest
   cent with a reconciliation note (Y). Session 1 asks how an amount of 2.345
   is billed. Obsolete reference: 2.35; informed reference: 2.34. Competing
   pages: the finance workflow with the old rule and the migration note with
   the new one.

The set is deliberately small. Each chain has one obsolete value, one
informed value and at least one competing page; the session-1 question asks
for the rule, not for a page, so a page's presence does not by itself answer
it.

### 2.3 What the calibration and the checker produce

The calibration report records, per task, the negative control's outcome and
the informed reference's outcome. A task enters the measured set only when
the control fails and the informed reference passes. The measured run
classifies every trial as X (obsolete), Y (informed) or other (failed), and
reports the obsolete-answer rate per arm, the paired comparisons against the
negative control, and the failure counts by category. A control arm that
lands nothing may still guess; project-specific values make a lucky guess
unlikely, and the calibration is what shows that the control fails.

## 3. The arms and the curator

### 3.1 The comparison the roadmap names

| Arm | What it is | What it isolates |
|---|---|---|
| `memkernel` | memkernel's store and retrieval, without a wiki | the value of persistent memory alone |
| `memkernel` + governed wiki-studio | memkernel and a governed wiki, with the export → review → promote → approve → import loop | the incremental value of the governed composition |
| `fs_grep` | files plus grep, curated by direct edits | the non-memory, non-gate control |
| negative control | no persistence or correction mechanism (the suite's `bare`; the prompt-length `placebo` arm remains a control if the suite keeps it) | what the model does without the mechanism; calibration must show it fails |

The composition arm is a new, versioned arm with its own configuration and
instruction. The 0.4.1 `wiki_studio` arm stays frozen: memkernel's
`config.frozen.json` records wiki-studio `v0.4.1`, commit `8b5c8af…`, and
the sha256 of
[`docs/agent-arm/config.frozen.json`](../../docs/agent-arm/config.frozen.json)
and [`docs/agent-arm/instruction.md`](../../docs/agent-arm/instruction.md)
([`config.frozen.json:25-41`](https://github.com/gosha70/memkernel/blob/v0.5.0/eval/lifecycle-suite/arms/wiki_studio/config.frozen.json#L25-L41)).
Neither file is edited or re-pinned; the new arm is a separate experiment,
pinned to the wiki-studio version that ships the composition (0.8.1 or
later) and to the memkernel version it runs against. Each arm in the new
comparison pins and hashes its model, harness, wiki-studio, memkernel, task
set and curator policy; a version change is a new arm, never an edit to a
frozen one.

### 3.2 The composition arm's workflow

The composition arm is the loop that
[`docs/quickstart-memkernel.md`](../../docs/quickstart-memkernel.md) executes:

- session 0 records the decision through memkernel and exports a draft
  through the gate;
- the curator reads the draft with `wiki-studio read --json`, corrects it,
  sets `status: stable` and `corrects: <memkernel_ref>`, lands it with
  `propose --from … --promote --by curator`, and approves it with
  `approve --by curator`;
- session 1 runs memkernel's governed `wiki_import` and recalls.

The curator step is part of the arm, not an optional addition. `approve`
refuses `status: draft` ([`api.py:799-800`](../../src/wiki_studio/api.py)),
and governed import imports approved revisions only, so an unedited draft is
invisible to the next session. The 0.4.1 instruction drafts pages as
`status: draft`
([`instruction.md:22`](../../docs/agent-arm/instruction.md)). A page in that
state cannot be approved and governed import never imports it, so in the
composition a curator step is what makes the page visible to the next
session. The 0.4.1 arm reads the shared wiki directly and has no such step;
it stays historical, and the composition requires a new arm.

### 3.3 Curator options

| Option | What it measures | Limitation |
|---|---|---|
| Scripted curator with a preregistered policy | the full gate and import path with a reproducible, auditable actor; approval decisions, queue age and gate behaviour under a fixed rule | it is a machine curator, so its queue age is machine time, not review time; the policy is part of the treatment and must be frozen |
| `auto_approve_on_promote` | the zero-review configuration: promotion approves the pages it wrote, under the promoter's actor | it removes the reviewed-proposal property under test; on a wiki with this policy an agent's promote can approve its own proposal, which `SECURITY.md` names; it also approves no drafts, so it still needs a status edit |
| Oracle curator, as an upper bound | the outcome with perfect curation through the gate; the difference from the scripted curator is curator error, and the difference from memkernel alone is what the composition adds | it is not a deployable workflow and its outcome is not a claim about achievable results |

**Recommendation: the scripted curator with a preregistered policy is the
primary composition arm.** Its policy is frozen before the run and hashed
with the arm. It may only use the exported draft and the task's correction
brief; it sets `status: stable`, checks that `corrects` names an existing
memory, writes `.base.json` from `read --json`, promotes and approves, or
refuses with the reason. It must not special-case task ids, and a retry on a
stale base revision must itself be part of the policy. The oracle curator
runs beside it as the upper bound, and the gap between the two is reported
as curator error. `auto_approve_on_promote` is not the primary arm because it
deletes the property the comparison exists to measure; at most it is a
preregistered sensitivity check of the zero-review floor, named as such
before the run.

### 3.4 The gate's own records, a requirement of the composition arm

The composition arm's wiki is governed: its manifest sets
`approval_required: true`, and the arm's protocol requires an approval for
every landed page. For every content page an arm lands, the end state is
checked against the gate's records, not just the reported tool calls:

- a committed receipt under
  `doc_internal/proposals/.applied/<name>/receipt.json` with
  `submission_digest`, `actor`, `started_at` and `committed_at`
  ([`promoter.py:1096-1116`](../../src/wiki_studio/promoter.py));
- an approval record under `knowledge/wiki/.audit/approvals/` for the page's
  live sha256, naming the approver and timestamp
  ([`review.py:13-14`](../../src/wiki_studio/review.py));
- `review_state` reporting `approved` with an `approved_sha256` equal to the
  page's end-state sha256
  ([`api.py:814-830`](../../src/wiki_studio/api.py));
- the audit archive `.audit/proposals/<name>/` with `plan.json`,
  `proposal.md` and `curator-delta.md`
  ([`promoter.py:750-837`](../../src/wiki_studio/promoter.py)); the receipt
  itself lives only in the `.applied/` directory, not in the archive
  ([`promoter.py:762-767`](../../src/wiki_studio/promoter.py));
- every current content page the arm landed is covered by those records. A
  page with no receipt or no approval record is counted and reported as a
  gate breach — a direct write, or a promotion without an approval — and the
  breach count is part of the arm's result. The `index.md` and `log.md`
  appends belong to the proposal's plan and are not separate pages.

`lint` must report zero violations on the end state. `findings` reports
curatorial attention, not gate breaches: a stale approval after a later
edit is a finding. Tool-call diagnostics such as the two in §1.2 are
supporting data, never a substitute for these records.

## 4. The roadmap's six questions, mapped

| Question | Measurement or existing evidence |
|---|---|
| Does governance improve task outcomes | The paired task success and failure categories across sessions in memkernel's suite, on the calibrated task set of §2, with the negative control and the three comparator arms of §3.1. No measurement able to discriminate the arms has been run. |
| Do corrections reach the agent | The obsolete-answer rate from §2's checker. Replacement is available today; deprecation and deletion need memkernel 0.7, which is not released, so the rate is complete only when it lands. |
| Can changes be explained | Counted from the end state with `review_state` and `findings`: the receipts, approval records, `.audit/` and page sources of §3.4 for every accepted revision. No new code; `docs/demo-correction-loop.md` shows the records exist for one chain. |
| Does failure recovery work | The loop test's retry property — a promote interrupted after its commit resolves from its receipt, and export or import run twice creates no duplicates — plus the Release A regression tests under controlled faults. Not an agent run ([`test_release_b_loop.py`](../../tests/integration/test_release_b_loop.py)). |
| What does curation cost | memkernel's token receipts, which need the per-group table of §5; the receipts and approval records give queue age (a receipt's `committed_at` to the approval record's `timestamp`) and the proposer, promoter and approver. Wall times are machine time on the measured path. |
| Can others adopt it | The demonstration's machine times now (the `demo-correction-loop` job, and the recorded run committed at `examples/correction-loop/runs/2026-11-04-wiki-studio-0.8.1-memkernel-0.6.0/`), labeled as machine time, in [`docs/demo-correction-loop.md`](../../docs/demo-correction-loop.md); a pilot (the roadmap's Launch sequence step 3) for people. |

## 5. Dependencies on memkernel

Listed, not built. The measurement is memkernel's to design, preregister,
budget and run.

1. **The arm and its curator step.** A new versioned arm with its own frozen
   configuration and instruction, the curator policy, and the gate-record
   check of §3.4.
2. **The task set and its calibration.** The chains of §2, the competing
   pages, the frozen prompts, and the runner change that stops copying the
   correction into every arm's second session.
3. **A per-group token table.** The 0.5.0 report has none, and without one
   the token totals across groups cannot be compared.
4. **The preregistration.** Hypotheses, arms, task set, calibration,
   checkers, model and versions, exclusions and the analysis, frozen before
   the measured run.
5. **The budget.** Model calls, tokens, trials and the run's cost, named
   before it starts.
6. **memkernel 0.7 for withdrawal.** Deprecation and deletion are absent from
   0.6.0; the obsolete-answer rate covers replacement only until they land.

This document does none of these. It writes no runner, statistics,
event-schema or task code; it edits no frozen arm file or recorded run; it
claims no gain. Its sources are memkernel's published files at `v0.5.0` —
[`report-0.5.0.md`](https://github.com/gosha70/memkernel/blob/v0.5.0/eval/lifecycle-suite/report-0.5.0.md),
[`preregistration.md`](https://github.com/gosha70/memkernel/blob/v0.5.0/eval/lifecycle-suite/preregistration.md)
(the `wiki_studio` arm is scoped to `lc-wiki` at
[24-26](https://github.com/gosha70/memkernel/blob/v0.5.0/eval/lifecycle-suite/preregistration.md#L24-L26)
and its comparison is at
[124-128](https://github.com/gosha70/memkernel/blob/v0.5.0/eval/lifecycle-suite/preregistration.md#L124-L128)),
the [arm configuration](https://github.com/gosha70/memkernel/blob/v0.5.0/eval/lifecycle-suite/arms/wiki_studio/config.frozen.json)
and the [task](https://github.com/gosha70/memkernel/blob/v0.5.0/eval/lifecycle-suite/tasks/lc-wiki-backoff/task.json)
— and this repository's files at the commit that carries this document. The
0.5.0 files are frozen and are cited, not edited.

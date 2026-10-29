# Runbook: how a feature gets its spec and its tests

**Goal.** Accurate specs a QA person or product owner can read without a
developer, and per-app Playwright tests derived from them with strong
coverage, for OJS, OMP and OPS (one FEATURE-MAP row per feature, anchored on
OJS). Every claim is driven on the screens before it ships, every spec gets
one readability pass, every suite runs green twice, and anything
security-shaped in released code is kept in the private security repo.
When a rule gets in the way of that, the rule changes.

This file and `docs/tracking/PROGRESS.md` are the source of truth; a session
becomes correct by reading them, never by memory. A session is either a
FEATURE session (one feature, then stop for the maintainer's review) or a
MAINTENANCE session (`MAINTENANCE.md`, with this loop binding underneath:
the housekeeping session builds pending rows and revisions through it);
the PROGRESS banner says whether the resident agent is active. Paths are
relative to the repo root; `../pkp-e2e-sec/` is the private security repo,
and its `security_policy.md` the rule for anything security-shaped.

## The loop

Each role's rules live in its brief template, `docs/process/briefs/<role>.md`;
the orchestrator renders briefs from them (`briefs/README.md`), judges
results, and alone writes PROGRESS rows and `app-changes.md`. Every agent that
drives screens opens with the Frame (`briefs/frame.md`), which sets what this
testing is and is not. A feature session does the feature and nothing else.
Every step ends in a file, and `.reports/<feature>/phase-status.md` gets one
line per gate passed (`<gate> · <date> · <file>`), appended by the
orchestrator.

1. **Claim.** `node bin/slot.js claim U<nn>` first: other slots' sessions
   may be picking from the same PROGRESS at the same time (harness.md
   "Slots"), and a refusal means another session holds the feature, so
   take the next pending row. Then set the row to `in_progress`. Gate: the
   row.
2. **Fleet prep.** `npm run fleet-prep -- --feature U<nn> [--reset]`.
   Gate: `.reports/<feature>/fleet.json`.
3. **Draft.** A spec author writes `docs/specs/U<nn>-<feature>.md` per
   TEMPLATE, all three apps from the start, Coverage rows classed and
   `planned`, no scenarios, open questions as `to drive:` footnotes
   (`briefs/spec-author.md`). Gate: the spec, lint zero.
4. **Harness.** Only when the author's return names a scenario key
   `scenarios.md` lacks: a harness agent builds it with its parity row and
   re-runs the shipped suites that seed through it (`briefs/harness.md`); a
   test author who meets a missing key at step 8 sends the loop back here.
   Gate: `.reports/<feature>/harness/harness-log.md`.
5. **Claim check.** `npm run seed-facts -- --check` to zero, then
   `node docs/process/lint/lint-spec.mjs --claims <spec>` into
   `.reports/<feature>/claims.txt`. The orchestrator cuts `claims.txt` into
   screen clusters seeded from the spec's surfaces table
   (`claimcheck-chunks.md`); fresh checkers drive every line
   (`briefs/claim-check.md`); with three or more chunks a merge agent writes
   `claimcheck-merge.md` (`briefs/merge.md`), with two or fewer the fold reads
   the chunk reports directly; a fold agent folds the change list into the
   spec (`briefs/fold.md`). Gate: `claims.txt`, `fold-log.md`, lint zero,
   `claims.txt` regenerated.
6. **Scenarios.** A fresh writer spends the Coverage table by class ("What
   the scenarios cover"),
   composes the canonical scenarios from the verified body, and turns the
   Coverage table into the "Left out" list after them
   (`briefs/scenario-writer.md`). Gate: scenarios in the spec, the
   Coverage table gone, lint zero.
7. **Readability.** One persona read of the body (`briefs/persona.md`), then
   one rewrite of the wording blockers (`briefs/rewrite.md`); no second read,
   no other persona anywhere in the feature. Gate: `persona.md`, lint zero.
8. **Tests.** One test author per app writes the suite and runs it green once
   (`briefs/test-author.md`); one fold agent folds the runs' findings, with
   `Basis: test run` on new entries (`briefs/fold.md`). The second green is
   CI's, never a local whole-suite run (it takes the VM up to an hour and
   holds the test lock every other slot waits on): commit the work on a
   branch named `U<nn>` (no `/`, or CI skips it), push it, and run `node
   bin/ci.js watch > .reports/<feature>/ci-run.log` in the background under
   the keepalive; all three apps' full suites on fresh boxes, 20–35 min.
   A red is fixed and pushed again (the newer push cancels the branch's
   older run), then watched again. Gate: `test-<app>-green.log`,
   `ci-run.log` ending green.
9. **Progress.** The orchestrator sets the frontmatter to `status: verified`
   (its one inline spec edit) and replaces the PROGRESS row: status, scenario
   count, tests per app, and a note in the fixed shape (tests per app ·
   register counts · one headliner ID · rarely-met states left out · open
   blocker · low-confidence IDs). Gate: the row, lint zero after the flip.
10. **Commit and push.** The feature branch, with the PROGRESS row
    committed on it, rebased onto `origin/main` and pushed there (`git push
    origin U<nn>:main`), then the remote branch deleted: the branch's green
    CI run was the full run, `main`'s own push run confirms it after the
    merge, and the app repos' PR checks call this `main`, so unpushed work
    counts for nothing. `.reports/` never (session scratch, gitignored, deletable
    after review; the kept checks under `shared/playwright/checks/` are
    the exception). App checkouts are read-only: pkp push URLs are
    disabled by construction, app changes go through maintainer-reviewed
    PRs, a bad push gets a follow-up commit, never a force-push. Before
    committing, `npm run check-models` must pass: it lists every agent of
    the session that was stopped or served another model and blocks on any
    but the security probe and a narrow rerun after a stop ("Model
    discipline"; for the probe, add `(finished on <model>)` to its
    finding's `verified` line). Gate: the
    commit on `origin/main`.
11. **Report.** What was built, the register highlights, anything
    low-confidence; if
    anything was routed to the private security repo, the verification
    probe (`briefs/security-verify.md`) has run, the orchestrator has
    committed and pushed the private repo, and the report gives counts only
    (the findings themselves go to the thread, "What goes where").
    Then stop; the next feature starts in a fresh session. Gate: `security ·
    <date> · none | routed, see pkp-e2e-sec` in phase-status.

## What goes where

| What | Where |
|---|---|
| Product findings: bugs, divergences, open questions, API misbehavior the browser's own traffic showed, or a direct check of an API no screen calls (the Frame's one exception), with no security dimension | the spec's Findings register; nowhere else (not `app-changes.md`, not a PROGRESS note). A new 🐞 entry needs no other step: `npm run backlog` lists it until the housekeeping session writes it up (MAINTENANCE "Issue reports") |
| A potential security concern, whatever branch carries it (one that no tagged release nor `ore` carries is labeled `unreleased`, a bare stable-branch commit included; its issue on the private tracker posts right after refinement, a released one's at the maintainer's word — maintainer, 2026-10-17) | the private security repo `../pkp-e2e-sec`, as its `security_policy.md` says: checked first against its findings and its copies of PKP's advisories (a known problem gets a sighting line, not a new file), one file per problem, verified by one targeted probe (`briefs/security-verify.md`) before the session report, then committed and pushed there by the orchestrator. Every finding added is posted in full in the session's thread with its path in the private repo (on the VM, in a post tagging @jarda.kotesovec alone, who watches over the security reports (regression reports tag @beaug alone; one watcher per kind, 2026-09-30), in every session, a developer's PR check included; no direct messages): Mattermost is private, the repos are public (maintainer, 2026-10-02). The content never appears in anything this repo carries: a spec, test, tracking file, PROGRESS note, commit message, branch name or pushed file |
| A plugin review's report (a third-party plugin for PKP's Plugin Gallery) | the private security repo's `plugin-reviews/` and the session's thread only (MAINTENANCE "Plugin review"); nothing about the plugin in anything this repo carries |
| A finding against an unmerged PR | the developer; the spec describes `main` (MAINTENANCE "A developer's PR fails the suite") |
| What a probe saw on another feature's screen | `docs/tracking/incidentals.md`, one line, written by the orchestrator from the fold log and the merge, only after grepping that feature's spec for it: a sighting the spec already states is dropped, one it contradicts names the rule or register ID it contradicts; the line names the account and the state the read was taken in (signed in or out, a window open over it, what the seed held), and a request it names as the one the screen sends, the role that sent it and the keys of its body, a quoted message as the page's or as one address's answer (four 2026-10-19 checks lost a drive to a row's wrong caller or surface), and its evidence names the kept script under `shared/playwright/checks/` beside any `.reports/` path, which stays in the slot that wrote it (U08, U22, U28, U29, U60 claim checks) |
| Process friction | `docs/tracking/friction.md`, one line, appended by the screen-driving agent itself |
| Build blockers and any app-code change | `docs/tracking/app-changes.md`, orchestrator only |
| Builder parity | `docs/tracking/parity-ledger.md` |
| A write-up for the team | `docs/reports/`, in the shape of `REPORT.md` (severity, summary, impact, steps, cause, proposed fix, evidence last), deleted once acted on; the register footnote keeps the pointer. A finding in a PR not merged yet goes to `docs/reports/pr-review/` until the merge |
| A spec's defect written up for the team | `docs/issues/`, in the shape of `REPORT.md`, by the housekeeping session (MAINTENANCE "Issue reports"), filed as a GitHub issue on pkp-e2e (reports filed before 2026-10-17 with `- **Security** unreleased` live on the private `pkp-e2e-sec` tracker) and deleted when the issue closes; the register footnote keeps the pointer. A change to an entry that has a filed report is carried to the report and the issue (MAINTENANCE "Keeping a report in step") |
| Process learnings | this file, TEMPLATE, PRINCIPLES or a brief template, through maintainer review; never a spec |
| Anything resolved | deleted; git keeps it. Tracking files hold what is open, and anything outside its canonical home is one sentence plus a link |

## What the scenarios cover

A feature's scenarios cover
everything important and everything a user meets in ordinary use,
whatever the count. The main and guard rows of the spec's classed
Coverage table (TEMPLATE "Coverage") are always covered, so a complex
feature grows by itself and stays one spec. A state rides as a bullet in
a scenario that passes through it or whose given already holds it; a
state nothing passes through gets a scenario of its own when an editor,
author or reviewer would meet it in an ordinary week of running the
journal, and goes under the section's "Rarely met" bullet otherwise,
never dropped silently, where the maintainer can pull it back. A
variant rides in a scenario already there or goes under "Nothing new to
test": a test that would assert nothing a covered row does not is
never written. Nothing is left out for size: no count per feature
sizes this, and a suite's length never cuts a scenario, CI takes
another shard instead (MAINTENANCE "Keep CI balanced").

## The multi-app rules

Test files cite these by number, so the numbers are stable.

1. **One spec, all three apps.** No per-app copies. An unmarked claim asserts
   "verified identical in every app that has the surface": for a shared code
   path the subclass-chain check (rule 8) is the evidence; for permissions,
   exclusivity or what a screen offers, additionally a live cross-app probe
   (rule 4); anything else is probed or gets a marker. Divergences carry an
   inline marker to the register; an absent feature gets a title badge such
   as `{OJS OMP}` and one absence paragraph written as an install fact.
2. **Scenarios live in the spec, common ones first,** then the app-specific
   ones; a per-app difference inside a common scenario is marked inline, and
   a scenario an app cannot run names its analogue or absence. A scenario
   added to a shipped spec goes last; the earlier numbers never move
   ("Revising a shipped feature").
3. **Tests are written per app, derived from the spec.** Each suite covers
   the common scenarios in its app's own context plus its app-specific ones;
   duplication between suites is fine. An absent feature costs one absence
   test with a positive control per assertion. What a test may assert is
   PRINCIPLES M3 and M4.
4. **Probing is cross-app by construction.** Every exclusivity claim ("only X
   can", "never shows") gets a read-only control probe in the other apps, and
   a probe item that spans apps is owned by one agent driving all fleets.
5. **Corrections to the OJS text are expected.** A finding that touches
   shared text is re-checked on OJS before the spec is final.
6. **Age guides the verdict.** Behavior untouched since the app's early years
   reads as intent; behavior that broke in a modernization window reads as
   decay. The verdict is the register badge plus one sentence; the
   archaeology stays in footnotes.
7. **Divergence or own feature?** Different parameters on existing machinery
   stay a register divergence; a difference that needs rules of its own
   (screens no spec claims, replacement scenarios) earns its own FEATURE-MAP
   row. Forked-copy code with identical logic is one feature, but every
   shared claim there needs probe evidence. OMP/OPS-only surfaces stay out of
   scope until the maintainer extends it. Size alone never splits a
   feature: a complex feature stays one spec and its scenario list
   grows ("What the scenarios cover").
8. **Look in the class hierarchy first.** For a load-bearing lib/pkp class
   read each app's subclass chain: an empty subclass is positive evidence of
   shared behavior, an override is intended divergence, a missing override
   is the classic silent one. `isOJS()`-style branches, registry and seed
   files and config-merge survivors are the secondary seams.

## Model discipline

- Opus 5.5 runs every role (maintainer, 2026-10-12); subagents inherit
  the session model, no per-role pins: no agent is launched on another
  model because its task looks light.
- A refusal or safeguard flag is not the end of the run: the agent
  carries on with its task after the notice instead of winding down, and
  the safeguard then serves the rest on a fallback model (Opus 5.5 →
  Opus 4.8, Sonnet 5.5 → Sonnet 5; seen in the transcripts 2026-10-17,
  where an agent that pressed on finished on Opus 4.8 and three that
  wrote up straight away left their work open). The agent cannot tell it
  was switched, so `npm run check-models` (the transcript) names the
  model, never the agent's own word. When the flag is a false positive on
  legitimate work (security work most often: the maintainers have access
  to PKP's advisories) and the piece is still undone, it is rerun cut as
  narrow as it goes (one task, such as one reproduction or the
  reproduction script for a security issue), briefed with what is
  already settled and made self-contained (the rows it acts on created by
  the agent itself on the disposable install, the clean-up said), in this
  order until one gets through (maintainer, 2026-10-17: never give up on
  a false positive, use the model that gets through): a fresh agent on
  the session's model, description ending "(narrow rerun)"; then Agent
  `model: sonnet`, "(Sonnet fallback)"; then `model: fable`, "(Fable
  fallback)" (not tried yet). `npm run check-models` allows these only in
  a session that recorded a stop. The session carries on with the result
  on its own model; specs and reports are written on Opus 5.5 only, and
  the result names the model that served it. When the flag is not a
  false positive, or every step above is stopped too: record the gate
  reached in the PROGRESS note and stop for maintainer review. A
  technical stall is not
  a flag: respawn on a narrower slice, at most twice.
- The one exception is the security verification probe: a stop there, or
  the rest of its run served on another model, does not hold up the
  feature. Its verdict stands with the model named on the finding's
  `verified` line, and a finding it could not settle stays `verified: no`
  for the maintainer. It writes only to the private security repo and its
  own folder, so nothing it produced reaches other work.
- The orchestrator never probes, verifies or edits a spec inline (the
  `status:` flip excepted); agents that drive screens are always fresh, one
  or two at a time, cut for about 40 browser calls each (an agent still
  finishes its chunk past that).
- Returns are pointers and counts, never findings; the orchestrator judges
  by files (`ls`, `wc -l`, `grep -c`), reads only what must be judged, and
  runs no explore or plan agents during a feature. Between gates the files
  under `.reports/<feature>/` are the status.
- When context runs low, or two launches in a row fail: finish the gate,
  commit and push what is commit-worthy, end; a fresh session resumes.
- **Keep the thread ticking while waiting.** A session that runs inside
  claude-threads (the Mattermost bot) is paused as idle after 10 silent
  minutes, and a background agent, a full suite or a CI run is silence to
  it. Whenever the next event is more than a few minutes away, arm a
  keepalive (a Monitor that ticks every 6 minutes, whatever is in flight:
  the bot warns after 7 idle minutes and pauses after 10; re-armed at its
  30-minute expiry) and post one line per tick: the
  gate that is running and what the files show, nothing else. The ticks
  double as the polling points for the finals and the CI run; the
  keepalive stops at the report, never earlier: a quiet tick is fine, a
  stopped Monitor with work in flight is a paused session whose runs die
  with it. A Playwright run can also wait behind another slot's run for
  the machine's test lock (harness.md "Slots"), so fleet-prep and any run
  that may queue go to the background under the keepalive, never in a
  foreground command; so does `node bin/ci.js`.

## Definition of done

Per feature: the spec is `verified` and lint-clean, all three apps are
covered per the multi-app rules, each suite is green twice, the PROGRESS row
is updated, everything is committed and pushed; team review of verdicts is never a gate.
Campaign: the unclaimed atom count in FEATURE-MAP is zero, every PROGRESS row
is `done` or `parked`.

## Resuming a feature mid-flight

When PROGRESS shows `in_progress` and the tree holds uncommitted work, read
`phase-status.md`, check the files it names exist, and re-run the first gate
whose file is missing. Only files count; a mid-feature commit's PROGRESS
note names the last gate reached.

## Revising a shipped feature

A revision grows a shipped spec's scenarios and suites. The body stays
verified, so there is no draft and no claim check. It starts in one of
two ways:

- **Planned items.** The spec's "Left out" list holds a **Planned**
  bullet (TEMPLATE "Coverage"): coverage owed on the spec that was not
  written on the spot, from an upstream sync, a coverage request or any
  other session. That bullet is the spec's one backlog. The housekeeping
  session revises one such spec at a time, every Planned item in one pass.
- **A rule change.** A new coverage or scenario rule leaves shipped specs
  behind. The maintainer opens the queue `docs/tracking/coverage-revision.md`,
  one row per spec, deleted when it empties, and launches each revision
  like a feature session, one at a time, in queue order.

Either way the revision works from one sheet,
`docs/tracking/coverage-revision/U<nn>.md`, written before the writer
starts and deleted when the revision closes: the spec's classed Coverage
table in TEMPLATE's draft shape, one row per Planned item or per row the
rule change reopens, each citing the body; `S<n>` in "Runs in" where a
scenario already covers the row, `planned` where none does, blank where
the writer decides; under the table the plan for each gap (rides in
`S<n>`, a scenario of its own, or no seed), the suite mismatches
`lint-spec.mjs --tests` reports and the bullets a suite does not assert.
The writer spends the table as "What the scenarios cover" says.

1. **Claim, fleet prep and the sheet**: steps 1 and 2, then the sheet
   unless the queue already holds it.
2. **Scenarios.** A scenario writer (`briefs/scenario-writer.md`, situation
   "revision") spends the classed table by class: reshapes the existing
   scenarios into TEMPLATE's shape sentence for sentence, adds a bullet to
   the scenario a gap rides in, appends a scenario for each gap that needs
   one (numbers never move: the suites' `S<n>` titles and the PROGRESS
   notes cite them), strips the coverage sentences ("scenario 9 runs the
   on end", "no scenario because…") from the "Settings that modify
   behavior" bullets so the section holds facts only, settles
   every test without a scenario and every scenario without a test the
   queue file lists (the scenario becomes a "Left out" item with its
   reason, or the test's behavior gets a scenario when the body states
   it), and writes the "Left out" list. A state with no scenario key goes
   to step 4 or under "No seed". Gate: lint zero.
3. **Readability** as step 7, the persona reading the changed and new
   scenarios only.
4. **Tests.** One test author per app (`briefs/test-author.md`, situation
   "revision") extends the suite: a test per new scenario, an assertion
   per bullet added to a scenario already tested, every title opening
   `S<n>`, the header's "not covered" block cut to register IDs; then the
   fold and the CI run as step 8. Gate: the green logs, `ci-run.log`,
   `node docs/process/lint/lint-spec.mjs --tests <spec>` zero.
5. **Progress, commit and push, report** as steps 9 to 11: the PROGRESS row in the
   fixed shape with the scenario count; the sheet deleted, with its queue
   row when it has one, and no Planned item left in the spec.

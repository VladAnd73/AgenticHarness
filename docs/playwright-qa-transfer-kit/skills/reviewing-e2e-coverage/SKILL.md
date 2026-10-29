---
name: reviewing-e2e-coverage
description: Use when validating or improving the e2e test coverage of a {{PROJECT_NAME}} feature - auditing whether existing Playwright specs actually exercise the FULL functionality and producing an actionable coverage-review report other workers can implement. Symptoms - "review the test coverage", "are these specs thorough", "validate/improve the test cases for feature X", "senior QA coverage review", shallow asserts, "check the button exists" anti-pattern, missing negative/edge/CRUD cases.
---

# Reviewing e2e coverage (senior-QA audit -> actionable report)

You are a **senior QA automation engineer** with experience in the product's domain. Given a
{{PROJECT_NAME}} feature and its existing Playwright specs, you validate the current coverage against
the feature's COMPLETE intended functionality and produce an **actionable coverage-review report** that
lets other workers implement the improvements without re-deriving your context.

**Core principle - assert at the right place, exercise the flow, cover all of CRUD.**
The anti-pattern this skill exists to kill: tests that assert a control merely *exists* or *is visible*.
A link test must **click the link and assert the destination page opened**; an action test must
**perform the action and assert the resulting data/state changed**. Read-only coverage is not coverage.

This is a **report-only** exercise: you DESCRIBE improvements, you do not implement them.

## When to use

- Auditing/validating an existing Playwright suite for a feature; asked to "improve the test cases".
- Hunting for coverage holes: missing CRUD (Create/Update/Delete), negative, or edge cases.
- Reviewing assertion quality (presence-only vs deep) before a suite is considered done.

Not for: writing/scaffolding a NEW spec (use `new-test`), fixing a failing/flaky spec (use
`investigating-e2e-failures` / `qa-e2e-test-only-changes`), or a ticket-driven pre-implementation test
analysis (use `analyzing-test-tickets`).

## Inputs you need before starting

- The **feature** under review (name + rough scope).
- **Where its specs live** - the exact branch/PR and tip commit. Specs for in-flight features are often
  NOT on `{{DEFAULT_INTEGRATION_BRANCH}}`; confirm the ref and check it out (read-only / detached is fine).
- The spec folder + page-object folder paths.

## Method

1. **Establish intended behavior from {{INTENT_SOURCE}} - do this FIRST.** Invoke **`{{INTENT_SKILL}}`**.
   The glossary gives you the **entities**; the feature description gives you the **context / user
   journeys**. This is your intent oracle: what the feature is SUPPOSED to do. Write down every intended
   capability.
2. **Enumerate the real, exposed capability from the backend.** Read `{{BACKEND_REPO}}` (read-only) -
   the feature's controller, routes, and views (server-rendered views for admin-panel features) - to
   list every **CRUD operation** and every **action-flow** the UI actually offers (e.g. create, edit,
   delete, republish, publish-to-a-destination, assign/unassign, retry/repair, toggle a flag, filter,
   paginate, navigate into a detail page). Ground the audit in real capability, not guesses.
3. **Audit every spec + page-object.** For each scenario: state what it asserts *today* and grade it
   against the Assertion-quality rubric below. Note which page-object helpers are presence-only.
4. **Trace every acceptance criterion to an assertion - no AC left untested.** Collect the ACs from the
   feature's tickets **and from their linked tickets** (a neighbour's AC is an inherited constraint on
   this feature, not background reading - see `analyzing-test-tickets` Phase B). Build an
   AC -> spec -> assertion-grade table. An AC with no row is a coverage hole even when the surrounding
   feature looks well covered.
   **Then test the complement of every AC that names a population.** "Feature X applies to premium
   records" silently asserts "...and standard records are unaffected" - and the unstated half is the
   one that breaks, because the specs everyone writes cover the named half. **Testing the feature's own
   population is not testing the change's blast radius.**
5. **Gap analysis** across three axes: **functional**, **negative**, **edge**. Explicitly separate:
   **CRUD gaps** (which write-paths - C/U/D - are never exercised, only Read) and **flow-depth gaps**
   (flows asserted by button-presence instead of execute-then-assert-outcome).
6. **Flag intent-vs-code conflicts.** When intended behavior ({{INTENT_SOURCE}}) and observed behavior
   (code/spec) disagree, FLAG it - do NOT silently canonize the code as "correct". Route it as a question
   for the product owner. Correctly-guarded known-divergences (e.g. `test.fixme` for a not-yet-shipped
   behavior) are fine; note them.
7. **Produce the report** in the shape below.

## Assertion-quality rubric (the heart of the review)

Grade every assertion. Every improvement should move an item up this ladder.

| Grade | What it looks like | Verdict |
|-------|--------------------|---------|
| **[Presence-only]** | Asserts a link/button/element EXISTS or is visible | the anti-pattern - flag it |
| **[Shallow]** | Clicks, then asserts only a flash/toast fired | partial - flash != outcome |
| **[Deep]** | Clicks a link -> asserts the **destination page** loaded (URL + a page-specific element/data); OR performs an action -> asserts the **persisted data / row / badge / status actually changed** | the target |

Rules the report must enforce:
- **One action -> multiple effects; verify them ALL.** A single button click usually has several effects.
  Classify them: (a) primary state change (persisted data / UI reflecting it - phase, list membership,
  status, count); (b) downstream integration call (a request sent to the distribution API,
  `{{VENDOR_A}}`); (c) secondary UX (banner / toast / dialog). Grade a test on whether it asserts (a)
  AND (b); (c) is a supporting check, never sufficient alone. A test asserting only (c) is **[Shallow]**
  by definition, regardless of how many banners it checks.
- **Downstream integration = a [Deep] assert too.** When an action is supposed to hit the distribution
  API (publish / republish / stop / pause / archive / activate), the report must require asserting the
  vendor actually received the request for the SPECIFIC item (its id) + destinations, via the reusable
  `{{MOCK_TOOL}}` helper (in the reference project `playwright/support/vendorAMock.ts`: `purgeLogs()` ->
  action -> `verifyVendorReceived*Update` / `waitForLogs`). If a vendor path/verb isn't modeled yet,
  recommend a new verify method / mock route - not dropping the assert.
- **A data assertion read off the app's OWN API/GraphQL response is NOT [Deep] - flag it.** If a value
  the page renders (status, name, date, amount, mapped field) is asserted by reading the app's own query
  response (a `readImportedRecord`-style GraphQL read) instead of the RENDERED UI, grade it **[Shallow]**
  - a green payload with a broken render is a false pass. [Deep] requires the rendered UI (page object
  reading the DOM). The app's own API is acceptable ONLY for navigation/setup (resolving an id/token to
  open the page) or a value with genuinely no UI surface; the only legitimate non-UI *assertion* is the
  outbound third-party contract via the mock transaction log (above).
- **Assert the RULE, not the ROW - a round-trip assertion is structurally blind.** If a test *types or
  seeds* a value and then asserts that same value comes back, it can only prove that storage and
  rendering agree. **It can never detect a wrong value the system computed for itself** - which is the
  entire class of bug where a field is populated by an integration, a template, a fallback or a
  precedence rule. Flag any assertion whose expected value originates from the test's own `fill()`, the
  seed, or the DB, when the field under test is one the SYSTEM derives. The fix is to derive the
  expectation independently - from the documented rule - and assert against that: not *"the URL is
  whatever I just typed"* but *"the URL matches the tenant's configured URL template, and is not an
  external or preview URL."*
- **A failure mode the fixtures cannot produce is a failure mode no test can catch.** When grading
  coverage, check the seed/mock actually admits the risky input, not just the happy one. A mock that
  returns a single canonical variant (one destination, one status, one state) makes the whole
  neighbouring-branch surface untestable while looking covered. Recommend the missing fixture variant -
  and treat "the bug does not reproduce on our stack" as a **fixture gap to close**, not as evidence the
  bug was uncatchable.
- **Links:** open the link, assert the correct page rendered (internal same-origin links are fully
  clickable - assert URL + destination content). Never "link is visible".
- **Flows must be EXERCISED end-to-end:** republish / publish-to-a-destination / assign / unassign /
  retry-repair / toggle-flag must be **clicked/performed** and their **outcome** asserted via in-depth
  checks (the changed data, the new UI state, the row/badge/status transition, AND the vendor request
  where applicable) - not button presence, and not a flash alone where a deeper observable state exists.
- **CRUD:** Create, Update, Delete are covered where the feature supports them - not only Read. Call
  out every write-path that is currently only observed, never executed.
- **Respect shared-stack constraints.** If provider APIs are unmocked on the e2e stack, do NOT recommend
  firing live provider-hitting jobs. Tier the recommendation: (a) deterministic minimum achievable now
  (flash + observable state transition), (b) full data-outcome flagged as needing a VCR cassette / mock
  (note the prerequisite, see `editing-backend-seeds-and-mocks` (not included in this kit)).

## Report shape (the required output - this IS the deliverable)

Write a single markdown report to a durable path (e.g.
`{{REPORTS_DIR}}/<feature>-e2e-coverage-review.md`; create the dir). It must contain, in order:

1. **Ground-truth sources used** - {{INTENT_SOURCE}} pages, tickets read (read-only), backend files,
   spec ref/commit.
2. **Feature model** - every user-facing capability from intent + backend: each CRUD op and each
   action-flow, named.
3. **Per-spec audit** - walk every spec + page-object; per scenario, what it asserts today + its grade.
4. **Coverage matrix** - capability x {covered / partial / missing} x {assert-quality: [Deep] /
   [Shallow] / [Presence-only]}. Make the holes obvious at a glance.
5. **Prioritized improvement backlog** (highest-impact first). **Every item is actionable:** WHAT to
   add/fix / WHERE (file path + spec/PO-helper name) / ASSERTION (the concrete assertion or flow to
   write, in words) / SEED (any seed / page-object / fixture / mock prerequisite). A different worker
   must be able to pick one item and implement it cold.
6. **Gaps by category** - CRUD gaps (C/U/D), flow-depth gaps, negative + edge gaps, intent-vs-code flags.

## Guardrails (hard)

- **Grading something [Shallow] obliges SOMEONE to deepen it - never just to record it.** Superficial
  tests are the worst kind of tests to have. This skill is report-only, so you do not fix it - but every
  [Shallow] grade must land in the report as **required work with a named owner and a concrete
  deepening**, never as an observation or an optional nice-to-have. A [Shallow] assert left merely noted
  is a permanent hole that shows green.
- **Add this to the rubric when grading: a test with NO DEMONSTRATED PRE-FIX FAILURE is [Shallow]**,
  regardless of how rich its assertions look. If it was never run against code carrying the bug it
  claims to guard, nothing proves it guards anything. Watch specifically for assertions sitting behind
  an earlier assertion that aborts on pre-fix code - they are never reached, so they are unproven, and
  the fix is to SPLIT the test so each rule has its own independent proof.
- **Report only.** No edits to specs / source / page-objects / seeds / mocks. No new spec files.
  Improvements are described, not implemented.
- **No push, PR, merge, or branch mutation.** Fetch + read only.
- **Developer tickets are STRICTLY read-only** - no edits, no comments, on ANY {{TRACKER}} ticket. All
  findings go in the report file.
- **Cross-repo:** if you find a seed/mock gap, NOTE it in the report as a prerequisite; do not edit
  anything outside your worktree. If you truly believe you must, DECLARE it and block for coordinator
  ack.
- Do not cross-contaminate separate checkouts of the same repo (e.g. an upstream checkout and a fork).

## Common mistakes

- **Grading a flash as a deep assert.** A toast is not an outcome; find the observable data/state change.
- **Auditing the wrong ref.** In-flight specs are usually on a feature branch/PR, not
  `{{DEFAULT_INTEGRATION_BRANCH}}`; confirm the tip commit and that you see the full spec set before you
  start.
- **Guessing capability instead of reading the backend.** The controller/views are the ground truth for
  what actions the UI actually exposes.
- **Canonizing code over intent.** Divergence from intent is a FLAG, not a spec to enshrine.
- **A backlog item that just says "improve X".** Not actionable. Name the file, the helper, and the
  exact assertion to write.

## Related skills

- **`{{INTENT_SKILL}}`** - REQUIRED, step 1: the intended-behavior oracle.
- **`analyzing-test-tickets`** - sibling report methodology (ticket-driven, pre-implementation).
- **`running-e2e-tests`** + **`starting-the-e2e-backend`** - OPTIONAL, only if you run a spec to confirm
  a specific uncertainty; the static audit is the required core.
- **`new-test`** - for actually implementing a backlog item into a spec (a separate, later task).
- **`sweeping-releases-for-e2e-coverage-gaps`** - for picking WHICH features to audit across releases.
- **Agent `senior-qa-e2e-reviewer`** - runs this skill as a dedicated report-only reviewer.

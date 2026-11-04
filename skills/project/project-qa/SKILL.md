---
name: project-qa
description: Test a feature against its acceptance criteria, find bugs, and perform a security audit. Use after implementation is done. Pass a feature name or ID as argument.
---

# QA Engineer

## Role
You are an experienced QA Engineer AND Red-Team Pen-Tester. You test features against acceptance criteria, identify bugs, and audit for security vulnerabilities.

## Before Starting
Work from the project root — `PLAN.md`, `features/`, and `docs/` paths are relative to it.

1. Read the feature spec `features/{id}-*.md` — user stories, acceptance criteria, edge cases, Tech Design
2. Read `PLAN.md` — project type, tech stack, constraints
3. Check recently implemented features for regression testing: `git log --oneline -10`
4. Check recent bug fixes: `git log --oneline --grep="fix" -10`
5. Check recently changed files: `git log --name-only -5 --format=""`
6. Identify the project's test and run tooling — look for `pyproject.toml`, `package.json`, `go.mod`, Makefile, `scripts/`, README build/run instructions. Never assume a framework; discover it.

**If the feature has no spec file, its Tech Design section is empty or still the template placeholder, or its Status is neither "Implemented" nor "In Review":**
> "This feature isn't ready for QA — it needs a spec (`/skill:project-write-spec`), a design (`/skill:project-architecture`), and implementation (`/skill:project-implement` — Status "Implemented") first."
→ Stop here.

## Workflow

### 1. Read Feature Spec
- Understand ALL acceptance criteria (Given/When/Then)
- Understand ALL documented edge cases
- Understand the tech design decisions
- Note any dependencies on other features

### 2. Run Existing Automated Tests
Run the project's test suite FIRST (whatever the tooling is — `python3 -m unittest`, `npm test`, `go test`, `make test`, Docker scripts...). Note any failures — these are regressions and must be treated as High bugs.

### 3. Manual Testing
Exercise the feature the way a real user would — through its actual surface: browser UI, CLI, HTTP API (`curl`), or library calls, depending on the project type:
- Test EVERY acceptance criterion (mark pass/fail): tick the spec checkbox for each pass (`- [x] AC-N`), and un-tick any criterion that regressed since the last run — a regressed criterion is a bug, note it as one
- Test ALL documented edge cases
- Test undocumented edge cases you identify
- If the feature has a browser UI: use the `playwright-cli` skill for browser automation if it is installed; if not, fall back to the `playwright` CLI directly or manual browser testing — never skip UI testing because the skill is missing. Check responsive layouts (mobile 375px, tablet 768px, desktop 1440px)
- If the feature is an API/CLI/service: test exit codes, status codes, malformed input, and empty-state responses directly

### 4. Security Audit (Red Team)
Think like an attacker, adapted to the project's attack surface:
- Authentication bypass attempts
- Authorization: can user/process A access B's data?
- Input injection: XSS, SQL/command injection, path traversal via any input point
- Whitelist/guard bypass: force non-whitelisted endpoints, unsupported methods, unexpected parameters
- Rate/abuse limits: rapid repeated requests, oversized payloads, concurrent writes
- Exposed secrets: check logs, error messages, responses, and committed files
- Sensitive data leaking in API responses or stored files

### 5. Regression Testing
Verify previously approved features still work:
- Check specs in `features/` with status "Approved"
- Test core flows of related features
- Verify no visual regressions on shared UI (if applicable)

### 6. Write Automated Tests
Turn passing manual tests into a permanent regression suite, using the project's existing test framework and layout conventions (e.g. `tests/`, co-located `*.test.ts`, `*_test.go`):

**What to unit test (evaluate each):**
- Isolated logic: parsing, validation, transformation, storage operations
- Error paths and edge cases (corrupt input, empty state, missing file)

**What NOT to unit test:**
- Pure presentation with no logic
- Logic already fully covered by end-to-end tests

For end-to-end coverage: one test per acceptance criterion, named in plain language, runnable with the project's test command. First read the tests `/skill:project-implement` already added — extend or fix the existing per-criterion tests; add new tests only for gaps (missed edge cases, regressions), never a parallel duplicate suite. Mock only external dependencies, not internal logic. Run to confirm all pass.

### 7. Document Results
- Fill in the spec's **QA Test Results** section — inside the feature spec file (NOT a separate file). The spec template ships with a placeholder in this section; replace the placeholder line, do not add a second section
- Use the structure from [test-template.md](test-template.md)
- Every run gets its own run block, including the first: write the results under a `### QA Run N — YYYY-MM-DD` heading (first run = `### QA Run 1`). Never write bare run content directly under the `## QA Test Results` heading — later skills and `/skill:project-doctor` resolve "the latest QA run" as the `### QA Run N` block with the highest N, and that only works if every run is wrapped. A run block spans from its `### QA Run N` heading to the next `### QA Run` heading or the end of the section — its `###` sub-headings (`Acceptance Criteria Status`, `Bugs Found`, `Summary`, …) belong to the run above them, even though they share the heading level
- Re-run rule: if the spec already has QA results, do NOT overwrite them — keep the full history: append the run block from [test-template.md](test-template.md) at the end of the existing **QA Test Results** section, with its heading renumbered to `### QA Run N — YYYY-MM-DD` (next N). Never add a second `## QA Test Results` section
- Re-test rule: before writing the new run block, re-test every bug whose latest Status is **Open** from earlier runs and account for each in the new block — mark it `Fixed (Run N)` when verified fixed, keep it `Open` when still broken (re-list it), and keep user-deferred bugs `Deferred`. A bug never re-tested is never `Fixed`

### 8. User Review
Present test results with a clear summary:
- Total acceptance criteria: X passed, Y failed
- Bugs found: breakdown by severity
- Security audit: findings
- Production-ready recommendation: YES or NO

Ask: "Which bugs should be fixed first?"

**If the recommendation is READY but Low/Medium bugs are still `Open`:** for each one, the user must explicitly choose *fix now* or *defer*. Record every deferred bug by changing its **Status** in the latest run block to `Deferred (user decision — <when/where>, <date>)` — e.g. `Deferred (user decision — Phase 1 bug-fix round, 2026-10-28)` — and bump **Last Updated**. Never set the spec Status to "Approved" while any bug in the latest run block is still `Open`: only `Fixed (Run N)` and `Deferred (user decision)` clear a bug, so Approved + `Open` contradicts the routing rules used by `/skill:project-help` and `/skill:project-doctor`, and forces every future QA re-run to re-test bugs nobody intends to fix. Bugs the user chooses to fix now keep `Open` and route to `/skill:project-implement` (Status stays "In Review").

## Context Recovery
If your context was compacted mid-task:
1. Re-read the feature spec you're testing
2. Check if you already added QA results to the spec: look for a `### QA Run N` block (or other non-placeholder content) under QA Test Results — the heading itself always exists from the template, so its presence proves nothing
3. Run `git diff` to see what you've already documented
4. Continue testing from where you left off — don't re-test passed criteria

## Bug Severity Levels
- **Critical:** Security vulnerabilities, data loss, complete feature failure
- **High:** Core functionality broken, blocking issues, any pre-existing test failure
- **Medium:** Non-critical functionality issues, workarounds exist
- **Low:** UX issues, cosmetic problems, minor inconveniences

## Important
- NEVER fix bugs yourself — that is for `/skill:project-implement`
- Focus: Find, Document, Prioritize
- Be thorough and objective: report even small bugs

## Production-Ready Decision
An **open bug** is a reported bug whose **Status** is not `Fixed (Run N)` and not `Deferred (user decision)` — deferred bugs are the user's choice and neither block approval nor block routing.
- **READY:** No Critical or High open bugs remaining
- **NOT READY:** Critical or High open bugs exist (must be fixed first)
- READY with remaining Low/Medium open bugs is only valid **after** the step 8 accept-or-defer pass: every user-accepted bug is converted to `Deferred (user decision — …)` first. "Approved" with a remaining `Open` bug is never a valid end state.

## Status Handling
Canonical definitions: the `STATUS LIFECYCLE` comment at the top of the spec.
- At QA start: set the spec's **Status** to "In Review"
- If production-ready: set **Status** to "Approved" — only after every user-accepted bug is converted to `Deferred (user decision — …)` (see step 8); Approved with a remaining `Open` bug is invalid
- If bugs remain: keep "In Review"
- Whenever you change the Status or write QA results, also update the spec's **Last Updated** date

## Checklist
- [ ] Feature spec fully read and understood
- [ ] Existing test suite run (failures logged as High bugs)
- [ ] All acceptance criteria tested (each has pass/fail; spec AC checkboxes ticked for passes, un-ticked for failures)
- [ ] All documented edge cases tested
- [ ] Additional edge cases identified and tested
- [ ] Security audit completed (red-team perspective, matched to the project's attack surface)
- [ ] Regression test on previously approved features
- [ ] Every bug documented with severity + status (Open/Fixed/Deferred) + steps to reproduce + automated-test coverage marker
- [ ] On a re-run: every previously Open bug re-tested and accounted for in the new run block (`Fixed (Run N)` / still `Open` / `Deferred`)
- [ ] Screenshots/evidence added for visual or behavioral bugs
- [ ] Automated regression tests written for all passing acceptance criteria (project test command passes)
- [ ] QA results written into the spec's existing QA Test Results section, under a `### QA Run N — YYYY-MM-DD` heading (no second section)
- [ ] User has reviewed results and prioritized bugs
- [ ] If Approved: no bug in the latest QA run is left `Open` — every user-accepted bug converted to `Deferred (user decision — …)` with Last Updated bumped
- [ ] Production-ready decision made
- [ ] Spec status set to "In Review" (at start) and "Approved" (only if production-ready)
- [ ] Spec **Last Updated** date bumped

## Handoff
If production-ready:
> "All tests passed! Status updated to **Approved**. Next step: deploy/release this feature, or run `/skill:project-write-spec` for the next roadmap feature (or `/skill:project-refine` on a feature that already has a spec)."

If any bugs were deferred, list them by ID with their deferral note in the handoff message, so the backlog stays visible (e.g. "2 bugs deferred to the Phase 1 bug-fix round").

If bugs found:
> "Found [N] bugs ([severity breakdown]). Status remains **In Review**. The implementation needs to fix these before approval. After fixes, run `/skill:project-qa` again."

## Git Commit
```
test({id}): Add QA test results for [feature name]
```

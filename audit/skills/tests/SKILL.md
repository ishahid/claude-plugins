---
name: tests
description: Read-only test-suite audit across every language in the workspace. Discovers unit, integration, and component test suites, researches current best practice for the exact test tooling found, maps test coverage against risk, and reports severity-ranked, evidence-backed findings on gaps, test design, determinism, speed, coverage gating, and CI integration.
argument-hint: "[path ...] [focus, e.g. \"gaps, flakiness\"] [--delegated]"
disable-model-invocation: true
---

# /audit:tests — Test Suite Audit

You are a senior engineer who specialises in testing, doing a **read-only** audit of the automated tests in this workspace. The question you answer is: **would these tests catch the bugs that matter, quickly and reliably?** Line coverage is one input to that answer, not the answer.

Discover the suites, research current best practice for the exact tooling, ask the user targeted questions at two gates, then report severity-ranked findings in chat. Be specific and terse. Don't praise, and don't pad with generic advice.

## Before you start

Read the shared audit contract and follow it throughout. It defines the ground rules, evidence and confidence tags, severity, the finding format, the gates, delegated mode, and the overlap rule:

```bash
cat "${CLAUDE_PLUGIN_ROOT}/references/contract.md"
```

Finding IDs use the prefix `TST-`.

## Input

`$ARGUMENTS` (all optional):

- **Paths:** limit discovery to these directories. With none, scan the whole workspace.
- **Focus:** free text such as "gaps, flakiness". Treat it as the Gate 2 priority answer and don't ask that again.
- **`--delegated`**, or a calling prompt from `/audit:all` that includes an inventory and Gate 2 answers: run in delegated mode.

## Scope

**In scope:** unit, integration, component, contract, snapshot, property-based, and mutation tests in any language, plus the test infrastructure around them: runners, config, fixtures and factories, test containers, mocks and fakes, coverage tooling, and the CI jobs that run them.

**Out of scope:** browser and full-system end-to-end suites (`e2e`). When `e2e` is not running, give them a light pass and say so. Performance and load tests: note whether they exist, but don't audit them.

## Phase 1: Discover

1. Read root-level docs (`AGENTS.md`, `CLAUDE.md`, `README*`, `CONTRIBUTING*`, `docs/`) for stated testing conventions and commands. Treat them as hypotheses.
2. Find repositories and workspace packages, then their test suites. Look for:
   - **Runners and config:** `jest.config.*`, `vitest.config.*`, `karma.conf.*`, `pytest.ini`/`pyproject.toml [tool.pytest]`/`tox.ini`/`noxfile.py`, `go test` (`*_test.go`), JUnit/TestNG in Maven/Gradle, `rspec`/`minitest`, `phpunit.xml`, `xunit`/`nunit`/`mstest` projects, `cargo test`, ExUnit, Swift/XCTest, Kotlin/Kotest.
   - **Test files** by convention: `*.test.*`, `*.spec.*`, `test_*.py`, `*_test.go`, `src/test/`, `spec/`, `tests/`, `__tests__/`.
   - **Supporting infrastructure:** fixtures, factories, builders, test containers or compose files, mock servers (MSW, WireMock, `responses`, `nock`), coverage config (`c8`/`istanbul`, `coverage.py`, JaCoCo, `go test -cover`, `simplecov`), and mutation tools (Stryker, mutmut, PIT).
3. For each suite, collect: path, language, runner and version, test types present (unit / integration / component / contract), counts of test files and test cases (`rg -c` on the runner's test declaration), source files covered, coverage tool and threshold, CI job that runs it, and the last commit to the tests.
4. Build the **risk map**, the core of this audit. For each unit, list its critical areas: authentication and authorisation, payments and money, data writes and migrations, public APIs, parsing of external input, concurrency, and anything the docs or user call critical. Then add **churn**: the files changed most in the last 6 months (`git log --since=6.months --name-only --format= | sort | uniq -c | sort -rn | head -30`) and the files touched by commits whose messages say fix, bug, hotfix, or revert. For each critical or high-churn file, note whether a test exercises it.

**Gate 1.** Show the suite inventory and the top of the risk map, then ask with AskUserQuestion:

- Is this inventory complete and correct? (Yes / Some are missing or wrong, tell me which)
- Are the critical areas right? (Yes (Recommended) / Add or remove some, tell me in Other)
- Which branch or environment is production? (The current branch (Recommended) / Another, name it)

## Phase 2: Stack baseline

For each distinct runner and language:

1. Pin down the details: runner version, assertion and mocking libraries, fixture approach, parallelism, coverage tool, snapshot usage, test data approach, and how integration tests get their dependencies (in-memory fakes, containers, shared environments).
2. Research current best practice **with web search, not memory**, for those exact versions: the runner's support status, its recommended configuration (isolation, parallelism, fake timers, strict mode), deprecated APIs, recommended lint rules for tests (e.g. `eslint-plugin-jest`/`vitest`, `flake8-pytest-style`), and current guidance for the framework under test (e.g. Testing Library for UI, the framework's own testing docs). Cite the source and date for each. If web search is unavailable, follow the contract's fallback.
3. Write a one-paragraph "what good looks like" baseline per stack.

**Gate 2.** Ask with one AskUserQuestion call. Skip any question already answered by `$ARGUMENTS`.

1. **Priority.** "Which matters most?" Options: Gaps on critical paths first, with the default order (Recommended) / Flakiness and reliability first / Speed and feedback loop first / Test design quality first. The default order is risk gaps → effectiveness → determinism → coverage gating → speed → maintainability → tooling.
2. **Commands.** "What may I run?" Options:
   - Static only: read tests and config, no installs (Recommended)
   - Also install deps (scripts off) and run the unit suites once, with coverage
   - Full: also run integration suites (only with containers the repo itself starts) and repeat the unit suites 3 times to detect flakiness
   - Explain in Other which suites are unsafe or slow.
3. **Depth.** "How deep?" Options: Deep on the suites covering critical areas, survey the rest (Recommended) / Broad survey of all / Deep on all.
4. **Steering.** "Known flaky tests, recent escaped bugs, or out-of-scope areas?" Options: None, proceed (Recommended) / Yes, describe them in Other.

Defaults if skipped: the default order, static only, deep on suites covering critical areas, nothing excluded.

## Phase 3: Audit each suite

Work through the dimensions in priority order. For each check, record what you looked for, how, what you found, and the severity and confidence. Read every hit in context before calling it a finding.

### Risk gaps

- For every critical area and high-churn file in the risk map: is it tested, and at the right level? A permission check tested only through a happy-path UI test is a gap.
- Files repeatedly touched by fix commits with no test added alongside the fix (`git show --stat` on those commits). Each one is an escaped-bug pattern.
- Error paths: are failures, timeouts, invalid input, and permission denials tested, or only success?
- Boundaries: integration points (DB queries, external APIs, queues) tested against something realistic at least once, not only mocked everywhere.
- Name the top 5 untested areas by risk, each with the file and why it matters.

### Effectiveness

- **Assertions:** tests with no assertions; tests whose only assertion is that a mock was called; tautological assertions (`expect(x).toBe(x)`, asserting the value just set up); `assert True`; and broad `toBeTruthy` or `not None` checks where a value is known.
- **Over-mocking:** the unit under test is itself mocked; mocks of things the team owns that would be cheaper to use for real; and mock setups longer than the test.
- **Snapshots:** large snapshots nobody reviews, snapshots of logic output, and snapshot files updated in the same commit as the code change without review signals.
- **Implementation coupling:** tests asserting private internals, call order, or CSS classes instead of behaviour, so they break on refactors and pass on bugs.
- **Mutation evidence:** if a mutation tool is configured, its last score. Otherwise, for one or two critical functions, reason about whether an obvious mutation (flipping a comparison, removing a check) would fail a test, and tag it `[Likely]`.

### Determinism

- Real time, dates, randomness, and timezones without fakes or seeds; real network calls; reliance on test order or shared mutable state; and filesystem or port collisions under parallel runs.
- Sleep-based waits (`setTimeout`, `time.sleep`, `Thread.sleep`) instead of waiting on a condition.
- Retries configured at runner or CI level, tests marked flaky or quarantined, and how long they have been quarantined (`git log -S`).
- With permission at the Full level: run the suite 3 times and list tests whose result changed.

### Coverage measurement and gating

- Coverage collected at all, and on which suites; the threshold and whether CI fails below it; whether it measures branches or only lines; and exclusions that hide important code (`/* istanbul ignore */`, `# pragma: no cover`, broad `omit` globs).
- Diff or patch coverage on PRs, so new code can't lower coverage silently.
- With permission: report the measured coverage per unit and the critical files below 50%.

### Speed and feedback loop

- Wall time per suite (with permission, or from CI logs if visible in config artefacts), the slowest tests, parallelism enabled, and expensive setup repeated per test instead of per suite.
- Whether developers can run one test file quickly, and a watch mode is documented.
- Test pyramid shape: counts of unit vs integration vs e2e. Flag an inverted pyramid that makes feedback slow.

### Maintainability

- Shared helpers, fixtures, and factories vs copy-pasted setup (find near-duplicate setup blocks); giant test files; unclear test names that don't describe behaviour; and dead tests for deleted code.
- Skipped and focused tests (`.skip`, `xit`, `xdescribe`, `@Disabled`, `@Ignore`, `pytest.mark.skip` without reason, `t.Skip`, `.only`, `fit`, `fdescribe`) with their age from `git blame`. A `.only` committed anywhere is at least Medium, because it silently disables the rest of the suite.
- Test data: realistic builders vs magic literals repeated everywhere, and personal or production data copied into fixtures.

### Tooling and CI integration

- Every suite runs in CI on every PR, and failures block merge. Find suites that exist but no CI job runs.
- Test lint rules enabled (no focused tests, no disabled tests without reason, expect in every test).
- Results reported (JUnit XML, annotations) so failures are readable, and artefacts (screenshots, logs, coverage) kept on failure.
- Test commands documented and consistent across repos (`test`, `test:unit`, `test:integration`).

## Phase 4: Cross-repo consistency

Skip this phase if there is only one unit. Otherwise compare units on: runner and version, mocking approach, fixture style, coverage tool and threshold, CI gating, flakiness handling, and test commands. Flag every place where two units solve the same problem differently, and name the better baseline and why.

## Phase 5: Report

In delegated mode, return the delegated report from the contract and stop.

Otherwise report **in chat only**. Write no files in the repo. Keep it under about 2,500 words, in this order:

1. **Headline:** three sentences: whether the tests would catch the bugs that matter, the single most serious gap, and the single cheapest high-value fix.
2. **Inventory:** the confirmed suite table, updated with anything learned, with test counts and pyramid shape.
3. **Risk map:** critical areas and high-churn files × tested (yes / partly / no), top 10 rows.
4. **Top findings:** at most 10, ranked per the contract, as a table with the contract's finding fields. Keep each cell to one line.
5. **Per-suite summary:** at most 5 bullets per suite, covering what isn't already in Top findings.
6. **Clean:** one line per clean dimension: "Clean: checked X, Y, Z."
7. **Cross-repo drift:** a dimension × unit table where units differ, with the recommended baseline.
8. **Quick wins:** findings with Effort S, as a checklist.
9. **Could not verify:** skipped checks, why, and what it would take.
10. **Open questions for the team.**

Finish with the contract's cleanup: delete your scratch directory and anything the audit started or built. Then offer to save the full report to a file outside the repo, or to turn the top gaps into tickets with suggested test cases. Do neither unless the user asks.

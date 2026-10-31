# P2P widening for deferred acceptance (#117): rules, failure paths, cost

Continues the `widen-p2p` work of b063 (selector `bdd8de0`, config keys `b561b7a`), now wired into
the verification path. Semantics approved by James 2026-10-22 (knowledge/decisions; `DECISIONS.md`
section "#117 P2P 預設範圍").

## What runs

For a task with a deferred `test_commit` (worker path and `cairnwork-verify`), after the worker is
done:

1. select existing test files on the base by `p2p_selection` (state config, one state per target
   repository): `whole-suite` (default), `module-dir`, or `off` (the per-repository opt-out);
2. run them on the **base** to find the tests that pass there (a test that fails or is skipped on
   the base is not a regression). A test file the test commit adds is not on the base, so never
   selected. A base test file the test commit changes stays selected: the tests in it that the
   test commit adds, changes or removes (by AST, as `deferred_tests.new_tests`) are left to the
   author's verifiers (counted as `changed_by_test_commit`); every other test the base passed in
   it is a P2P test, bound by function (never the whole file, which on the judged commit also
   holds the test commit's tests). Before, the whole changed file was left out, so a node-id
   verifier on it left the file's other tests unchecked;
3. run exactly those base-passing tests on the judged commit as one more verifier
   `p2p-<applied mode>`; Core must see it pass like any other verifier. Every base-passing node id
   the targets cover is bound (`nodes`, `nodes_sha256`): a run that exits 0 but did not run one of
   them (for example a parametrisation built from candidate code that no longer yields that case)
   is not a pass, and is not re-run; the absent ids are recorded as `missing`.

`module-dir`: the directories holding a test for a changed file (by name `test_<stem>.py` /
`<stem>_test.py`, or by the mirrored package directory); every test directly in such a directory
is selected. On a flat layout `tests/test_base.py` therefore brings in `tests/test_sibling.py`
(the regression of the 2026-10-22 measurement); before, only the name-matched file ran.

## Failure paths (none can end VERIFIED)

Since #234 a failed base probe is UNCOMPARABLE (no evidence about the base), not a refusal: Core is
never asked and no receipt exists. `cairnwork-verify` reports `status: "UNCOMPARABLE"`; the worker
path ends FAILED with reason `UNCOMPARABLE: P2P_BASE_PROBE_UNUSABLE: ...` when the worker ran as
another uid (`agy_run_as_user`), else plainly `P2P_BASE_PROBE_UNUSABLE: ...`. A probe that worked
but found no base-passing test (no degradation) is still only recorded (`targets: 0`).

Since #234 the `module-dir` files are also probed on the unchanged base before the worker starts
(`p2p.base_env_check`). If that probe fails the same way, the attempt ends there with
`UNCOMPARABLE: BASE_ENV_FAILED: ...` (no `WORKER_STARTED`, isolated or not), so a flat layout whose
probe overflows or hangs no longer reaches the rows below.

| Situation | Result |
|---|---|
| base probe leaves a process behind (or the process list cannot be read) or changes the checkout, in any mode (#285), or leaves forged bytecode (#481) | task UNCOMPARABLE, `P2P_BASE_PROBE_UNUSABLE: base-probe-survivors` / `base-probe-mutated` / `base-probe-forged in <mode> mode`; no narrower mode is tried (it would be weaker evidence). Before the worker (`base_env_check`): `BASE_ENV_FAILED`. Before #285 the candidate run blocked on the base's own leftover (false FAILED) |
| base probe times out, reports nothing usable, or its report exceeds the 4 MiB report cap (a suite too large for one guard report; #184) in `whole-suite` | degrade once to `module-dir`; recorded as `degraded: base-probe-timeout` / `base-probe-failed` / `base-probe-report-over-cap` |
| degraded to `module-dir` but it would run the same files (flat layout) | task UNCOMPARABLE (#234; before: REFUSED), `P2P_BASE_PROBE_UNUSABLE: <reason>; module-dir selects the same files` (no second probe) |
| `module-dir` (or the degraded run) cannot be probed either | task UNCOMPARABLE (#234; before: REFUSED), `P2P_BASE_PROBE_UNUSABLE` |
| degraded to `module-dir` and it selects no test file, or none of them passes on the base | task UNCOMPARABLE (#234; before: REFUSED), `P2P_BASE_PROBE_UNUSABLE` (a failed probe is never "nothing to run") |
| order of the targets (#287) | the order the base probe ran them in (files, then tests within a split file), never sorted; before #287 sorted ids could run an order-dependent test before the test it depends on and fail a correct fix |
| candidate P2P run exceeds the budget | the observation is not a pass, Core says not verified (no re-run) |
| a P2P run fails on the candidate only because a test failed | re-run once; a pass on the re-run is what Core sees (same verdict as a clean pass) and the first run is recorded (`rerun`: failed tests (sanitised), returncode, timed_out, mutated, survivors, ran; bound into the re-run's artifact hash); the task result's `p2p` also carries `p2p_rerun_passed` (true: passed after re-run; false: failed again; absent: clean pass or no re-run), so reports can separate the cases; a second failure blocks |
| a P2P run fails for any other reason (checkout mutated, surviving process, oversized log, no usable guard report) | blocks as it is, no re-run |
| a P2P run (or its re-run) exits 0 but lacks a bound base-passing node id | not a pass, no re-run; `missing` lists the absent ids (first 50, sanitised; not in the hashed note, which is written before the run) |
| no base-passing test selected (no degradation) | only the author's verifiers run; recorded (`targets: 0`) |
| author verifier id equals `p2p-<mode>` | REFUSED, `P2P_VERIFIER_ID_CLASH` |

`p2p_time_budget_seconds` (default 300) bounds each probe or run, so the worst case adds three
budgets (probe, degraded probe, candidate run), four when a failing candidate run is re-run. A base test file the test commit changes adds its unchanged tests to the probe and the candidate run, under the same budget per run; an overrun follows the rows above. Tasks without a `test_commit` are unchanged.

**Default per entry path (#174).** Intake (`cairnwork-route`, the issue runner) defaults `p2p_selection` to `whole-suite`, budget 300 s. A `TaskSpec` built directly (`pipeline.run_task`, `scripts/drill_*.py`) is a library/drill path and defaults to `off`: it has no P2P unless the caller sets `p2p_mode`. The constants live in `p2p_selection.py` (`DEFAULT_MODE`, `DIRECT_MODE`, `DEFAULT_BUDGET_SECONDS`).

## Where the rule is recorded

Core's notarisation contract is unchanged. The rule (`configured`, `applied`, `degraded`, budget,
counts, `targets_sha256`, `nodes`, `nodes_sha256`) is a JSON note bound into the p2p observation's artifact hash (so the
Core record binds it), written as `p2p-selection.json` beside the p2p verifier log, and returned as
`p2p` by `cairnwork-verify` and in the task result. The exact test list is also part of the hashed
argv.

## Cost (measured 2026-10-22, M5, `scripts/measure_p2p.py`)

One candidate that appends a marker to a source file, one deferred test; seconds for the whole
`cairnwork-verify` call, no verifier account, Seatbelt sandbox.

| Repository | tests | off | module-dir | whole-suite |
|---|---|---|---|---|
| demo fixture (`cairnwork demo` layout, 2 tests) | 2 | 1.5 s | 2.5 s | 2.4 s |
| more-itertools (`ab-repos`, 2 flat test files, ~9,000 tests) | ~9,000 | 4.0 s | 23.8 s | 23.7 s |

Reading: the added cost is about one extra pytest run on the base plus one on the candidate
(about 20 s for ~9,000 fast tests). more-itertools has a flat test directory, so `module-dir`
selects the same two files as `whole-suite`; the two modes differ only on layouts with nested test
directories. Single runs, one machine; a suite with slow tests is bounded by the budget, not by
this number. Not measured: a repository whose whole suite exceeds the 300 s budget (the timeout
and degrade paths are covered by tests with a 5 to 10 s budget instead).

## For the third A/B round (to bb)

Pre-register the two catch rates **separately**: the regression class (P2P: a change that breaks
an already passing test) and the F2P class (the deferred tests fail). If the ground truth
includes whole-suite regressions, the regression catch rate is close to 100% by construction
under the new default and must not be pooled with the F2P rate. The harness passes its P2P list
explicitly through the manifest, so changing the product default does not alter the frozen
measurement.

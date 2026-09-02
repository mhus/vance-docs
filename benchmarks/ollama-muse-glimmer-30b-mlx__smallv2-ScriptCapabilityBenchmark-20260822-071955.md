# Vance Benchmark - ollama-muse-glimmer-30b-mlx__smallv2-ScriptCapabilityBenchmark-20260822-071955

- **Started:** 2026-08-22T07:19:55.657932Z
- **Judge:** gemini-gemini-2.5-pro
- **Knobs:** {chatTimeoutS=600, waitBudgetMinS=300}
- **Score model:** v2-graded
- **Total tests:** 5
- **Passed:** 5 / 5 (100%)
- **Average score:** 0.964
- **Total LLM time:** 847.3s
- **Total tokens (in / out):** 742.6k / 4.6k (21 round-trips)


## script-javascript

| Test | Pass | Score | Time | In | Out | Calls | Reason |
|------|------|-------|------|----|-----|-------|--------|
| `executesJavaScriptJsonTransform` | OK | 1.00 | 130.0s | 122.6k | 881 | 3 | tool=execute_javascript, expected output present — 100% — 3/3 checks |

<details><summary>checks</summary>

| Check | Kind | Earned | Weight | Note |
|-------|------|--------|--------|------|
| `turn-completed` | stage | 1.50 | 1.50 |  |
| `tool-executed` | check | 2.00 | 2.00 | tool=execute_javascript |
| `expected-output` | counted | 2/2 | 2.00 | all present |

</details>

| `executesJavaScriptPrimes` | OK | 1.00 | 114.5s | 122.8k | 779 | 3 | tool=execute_javascript, expected output present — 100% — 3/3 checks |

<details><summary>checks</summary>

| Check | Kind | Earned | Weight | Note |
|-------|------|--------|--------|------|
| `turn-completed` | stage | 1.50 | 1.50 |  |
| `tool-executed` | check | 2.00 | 2.00 | tool=execute_javascript |
| `expected-output` | counted | 2/2 | 2.00 | all present |

</details>

| `executesJavaScriptSum` | OK | 1.00 | 150.8s | 122.7k | 541 | 3 | tool=execute_javascript, expected output present — 100% — 3/3 checks |

<details><summary>checks</summary>

| Check | Kind | Earned | Weight | Note |
|-------|------|--------|--------|------|
| `turn-completed` | stage | 1.50 | 1.50 |  |
| `tool-executed` | check | 2.00 | 2.00 | tool=execute_javascript |
| `expected-output` | counted | 1/1 | 2.00 | all present |

</details>


## script-python

| Test | Pass | Score | Time | In | Out | Calls | Reason |
|------|------|-------|------|----|-----|-------|--------|
| `executesPythonPrimes` | OK | 0.82 | 102.0s | 87.2k | 806 | 5 | tool=python_run, missing [97] — head: {"id":"0d913f62","status":"FAILED","command":".venv/bin/python 'primes.py'","durationMs":21,"lastOutputAt":"2026-08-22T07:19:52.831311Z","exitCode":2,"stdoutPath":"/Users/hummel/sources/mhus/vance-wb/… — 82% — 2/3 checks · missed: expected-output(1/2) |

<details><summary>checks</summary>

| Check | Kind | Earned | Weight | Note |
|-------|------|--------|--------|------|
| `turn-completed` | stage | 1.50 | 1.50 |  |
| `tool-executed` | check | 2.00 | 2.00 | tool=python_run |
| `expected-output` | counted | 1/2 | 2.00 | missing [97] |

</details>

| `executesPythonStringReverse` | OK | 1.00 | 349.9s | 287.2k | 1.6k | 7 | tool=execute_python, expected output present — 100% — 3/3 checks |

<details><summary>checks</summary>

| Check | Kind | Earned | Weight | Note |
|-------|------|--------|--------|------|
| `turn-completed` | stage | 1.50 | 1.50 |  |
| `tool-executed` | check | 2.00 | 2.00 | tool=execute_python |
| `expected-output` | counted | 1/1 | 2.00 | all present |

</details>


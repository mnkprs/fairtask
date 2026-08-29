# Trajectory — pytest-dev__pytest-7939 — baseline (baseline-rerun)
Model: `claude-opus-5` · stratum: **unfair_tests** · human labels: underspecified=0, false_negative=2, filter_out=true

## Agent instructions
### Main agent system prompt
```text
You are screening a candidate task for a software-engineering benchmark.
A task = a GitHub issue + the repository at the commit before the fix + hidden tests from the fixing PR.
An engineer (or model) will be shown ONLY the issue text and the repository, must write a fix without asking
questions, and is then graded by applying the PR's test patch and running the FAIL_TO_PASS tests.

That setup is only fair if two assumptions hold. Score each on a 0-3 scale.

## Axis 1 — underspecified: is the issue text well-specified enough for a meaningful attempt?
Imagine an experienced engineer with full codebase access but no ability to ask for clarification.
- 0: The issue is well-specified and it is clear what is required for a successful solution.
- 1: There are some blanks to fill in, but there is a sensible interpretation of what is required.
- 2: The issue is vague and there is room for ambiguity. It is unclear what a successful solution would look like.
- 3: It is almost impossible to understand what you are being asked to do without further information.

## Axis 2 — false_negative: are the tests well-scoped so that ALL reasonable solutions to the issue pass?
The tests were written with one particular solution (the gold patch) in mind. The most common problem is a subtle
discrepancy between the tests and the issue text: the tests rely on a new function, parameter, variable name,
error message or exact output format that was introduced in the gold patch but is not mentioned in (or differs from)
the issue. Remember the engineer never sees the PR or the tests.
- 0: The tests perfectly cover all possible solutions.
- 1: The tests cover the majority of correct solutions; some unusual solutions may be missed.
- 2: The tests work, but some perfectly reasonable solutions would be missed by the tests.
- 3: The tests are too narrow/broad, or they look for something different than what the issue is about.

## Decision
"usable" if both scores are <= 1; otherwise "flag".

Answer with a JSON verdict matching the required schema.
```

### Task prompt
```text
# Candidate task: pytest-dev__pytest-7939
Repository: pytest-dev/pytest @ 65e6e39b76c236999fc53823892c26367a85a8f8 (version 6.2)

## Issue text (this is ALL the solver will see)
<issue>
[Feature] Allow a --sw-skip shorthand cli arg like --sw itself permits
The stepwise plugin exposes a shorthand option for the stepwise itself, however it requires a longer arg only for skip, I think these should be consistent and should offer shorthand versions for both.

'''python
def pytest_addoption(parser: Parser) -> None:
    group = parser.getgroup("general")
    group.addoption(
        "--sw",
        "--stepwise",
        action="store_true",
        dest="stepwise",
        help="exit on test failure and continue from last failing test next time",
    )
    group.addoption(
        "--stepwise-skip",
        action="store_true",
        dest="stepwise_skip",
        help="ignore the first failing test but stop on the next failing test",
    )
'''

Expected:
`pytest --sw-skip`
</issue>

## Gold patch (the original PR's code change — the solver does NOT see this)
<gold_patch>
diff --git a/src/_pytest/stepwise.py b/src/_pytest/stepwise.py
--- a/src/_pytest/stepwise.py
+++ b/src/_pytest/stepwise.py
@@ -1,5 +1,6 @@
 from typing import List
 from typing import Optional
+from typing import TYPE_CHECKING
 
 import pytest
 from _pytest import nodes
@@ -8,6 +9,11 @@
 from _pytest.main import Session
 from _pytest.reports import TestReport
 
+if TYPE_CHECKING:
+    from _pytest.cacheprovider import Cache
+
+STEPWISE_CACHE_DIR = "cache/stepwise"
+
 
 def pytest_addoption(parser: Parser) -> None:
     group = parser.getgroup("general")
@@ -15,12 +21,15 @@ def pytest_addoption(parser: Parser) -> None:
         "--sw",
         "--stepwise",
         action="store_true",
+        default=False,
         dest="stepwise",
         help="exit on test failure and continue from last failing test next time",
     )
     group.addoption(
+        "--sw-skip",
         "--stepwise-skip",
         action="store_true",
+        default=False,
         dest="stepwise_skip",
         help="ignore the first failing test but stop on the next failing test",
     )
@@ -28,63 +37,56 @@ def pytest_addoption(parser: Parser) -> None:
 
 @pytest.hookimpl
 def pytest_configure(config: Config) -> None:
-    config.pluginmanager.register(StepwisePlugin(config), "stepwiseplugin")
+    # We should always have a cache as cache provider plugin uses tryfirst=True
+    if config.getoption("stepwise"):
+        config.pluginmanager.register(StepwisePlugin(config), "stepwiseplugin")
+
+
+def pytest_sessionfinish(session: Session) -> None:
+    if not session.config.getoption("stepwise"):
+        assert session.config.cache is not None
+        # Clear the list of failing tests if the plugin is not active.
+        session.config.cache.set(STEPWISE_CACHE_DIR, [])
 
 
 class StepwisePlugin:
     def __init__(self, config: Config) -> None:
         self.config = config
-        sel
…[5545 more chars]
```

## Execution

- **session** `301e5549-eedb-4ec9-8210-d3cde4c6f9f6` · tools: StructuredOutput · subagents: claude, Explore, general-purpose, Plan, statusline-setup

#### judge/main → **final verdict**
```json
{
  "decision": "usable",
  "underspecified": 0,
  "underspecified_rationale": "The issue is precise: it quotes the exact `pytest_addoption` function in `src/_pytest/stepwise.py` and states the expected outcome, `pytest --sw-skip`, i.e. adding a shorthand alias for `--stepwise-skip` mirroring `--sw` for `--stepwise`. An engineer needs only to add the `\"--sw-skip\"` string to the existing `group.addoption(...)` call. The rest of the gold patch (refactoring StepwisePlugin registration, cache constant) is unrelated cleanup not required by the issue.",
  "false_negative": 0,
  "false_negative_rationale": "The single FAIL_TO_PASS test, `test_run_with_skip_option[--sw-skip]`, simply parametrizes the existing skip test with the new flag and runs `runpytest(\"-v\", \"--strict-markers\", \"--stepwise\", \"--sw-skip\", \"--fail\", \"--fail-last\")`, asserting the same stdout lines as the pre-existing `--stepwise-skip` case (e.g. `\"test_success_before_fail PASSED\"`, `\"test_fail_on_flag FAILED\"`). Any implementation that registers `--sw-skip` mapped to the `stepwise_skip` dest passes; no new function names, messages or output formats introduced by the gold patch are asserted. The extra test `test_stepwise_output_summary` is not in FAIL_TO_PASS and its expected strings (\"stepwise: skipping 4 already passed items.\") match the pre-existing message format, so it does not constrain the solution either.",
  "evidence": [],
  "confidence": 5
}
```


## Result
- subtype: success · turns: 2 · 12s · cost $0.065 · tokens in/out/cache: 2/957/1932

### ✅ Verification passed
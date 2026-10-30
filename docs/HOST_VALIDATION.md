# Native host validation — 2026-10-29

Date uses America/Chicago. Tests ran on a Linux ARM64 machine against the merged
PR #13 source, `c5a90c2cb30c8f6296c39e5bee94bd6af685e6c5`, followed by the four
review fixes in this change. The merge is already on `main`; its
[GitHub validation run passed](https://github.com/vbasin/claude-kit/actions/runs/41002247871).

## Observed behavior

| Check | Codex CLI 0.164.0-alpha.11.1 | Grok Build 1.0.60 |
| --- | --- | --- |
| Project skill discovery | `kit-deliver` discovered and read in a live model session | `grok inspect` discovers `kit-deliver` after project trust |
| Native hook discovery | SessionStart policy observed with normal config loading | `grok inspect` lists the project Bash hook after trust |
| Harmless Bash denial probe | Actual shell call blocked by the native PreToolUse hook | Direct adapter returns deny; model-run enforcement remains unverified |
| Deliberate failing gate | Manual verifier exits 1; automatic Stop hook reports both failed tests and continues the turn | Manual verifier exits 1; live model session blocked by expired authentication |
| Corrected gate | Manual verifier exits 0 after changing subtraction to addition | Pending live model test |
| Independent reviewer | Actual `spawn_agent` call with `agent_type: kit_reviewer`; review completed with no findings and no edits | Pending live model test |

The native Stop failure was observed on the merged source. The corrected-code
phase used a refreshed installation containing the four review fixes. Refreshing
both host installations correctly reported `installed` for the portable updates.

This is a bounded smoke test, not a claim of host parity or improved task quality.
Claude was not tested. Windows process-tree cleanup was not tested on Windows.
The Grok installation also discovers an existing user-level Claude-compatible kit
plugin: inspect overlapping hooks before treating it as an isolated native run.

## Configuration and trust matter

An initial Codex experiment used `--ignore-user-config`. That invocation discovered
the portable skill but did not expose the named reviewer or run the project hooks,
even with a project trust override. With normal config loading, the same files
exposed `kit_reviewer`, supplied the SessionStart policy, and denied the probe.
Do not use that initial invocation as evidence that native hooks work or as a
recommended native smoke command.

For this automation, the generated hook commands and scripts were inspected first.
Codex used a per-invocation project trust override and the documented
`--dangerously-bypass-hook-trust` option for those vetted hooks; no persistent Codex
hook trust was written. This does not test the interactive `/hooks` trust flow.
Normal installation should use `/hooks` to review and trust hook definitions.
See [OpenAI hook documentation](https://learn.chatgpt.com/docs/hooks).

Grok initially excluded the untrusted project's skill, instructions, and hook.
`grok --trust inspect` then discovered all three and persisted trust for this newly
created smoke repository. The live request failed before inference because saved
authentication was rejected (`invalid_grant` / not signed in). Run
`grok login --device-code` in an operator terminal, then repeat the live test.
The operator chose to leave live Grok testing pending for this change.
Do not put credentials in evidence files. Grok's passive Stop event cannot enforce
verification; explicitly invoke the manual verifier before reporting.
See [Grok hook documentation](https://docs.x.ai/build/features/hooks).

## Reproduce in a small repository

Use separate new Git repositories for Codex and Grok. Create `calculator.py`:

```python
def add(a: int, b: int) -> int:
    return a - b  # Deliberately wrong for the initial gate.
```

Create `test_calculator.py`:

```python
import unittest
from calculator import add

class CalculatorTest(unittest.TestCase):
    def test_positive(self):
        self.assertEqual(add(2, 3), 5)

    def test_negative(self):
        self.assertEqual(add(-2, -3), -5)
```

Put this trusted configuration in `.kit/kit.json`:

```json
{
  "verification": {
    "enabled": true,
    "gates": [{
      "name": "calculator-unit",
      "paths": ["calculator.py", "test_calculator.py", ".kit/*"],
      "argv": ["python3", "-m", "unittest", "-v", "test_calculator"],
      "timeout_s": 10
    }]
  },
  "guards": {
    "patterns": [{
      "regex": "KIT_GUARD_PROBE",
      "decision": "deny",
      "reason": "Harmless kit smoke denial probe"
    }]
  }
}
```

Install with `install_native.py --repo PATH --host codex` or `--host grok`, inspect
and trust the generated configuration, then commit the initial fixture. Ignore
`__pycache__/`. Scope the session to `calculator.py` edits and prohibit changes to
the verifier, tests, and hook settings.

1. Ask the host to use `kit-deliver`, report discovery, and execute exactly
   `printf KIT_GUARD_PROBE` once. Expect denial; do not retry around a denial.
2. Run `python3 <skill>/scripts/stop_verify.py --manual calculator.py`. Expect exit
   1 and two failed tests. `<skill>` is `.agents/skills/kit-deliver` for Codex or
   `.grok/skills/kit-deliver` for Grok.
3. In a separate Codex phase, add only a comment to `calculator.py` and attempt to
   finish without manually verifying. Expect the Stop hook to report failure.
   Leave arithmetic unchanged for this phase and report the failure honestly.
4. Ask the host to correct subtraction to addition, run the same manual verifier,
   and request one independent reviewer. Codex should use `kit_reviewer`; Grok
   should use an available native subagent with the installed reviewer brief.
5. Inspect tool events and results, not only the model's summary. Expect the
   corrected gate to exit 0 and the reviewer to finish without changing files.

## Four PR #13 review fixes

- Non-boolean `verification.enabled` values now fail strict configuration loading
  before selecting gate mode; malformed values cannot silently suppress pytest.
- Candidate evaluation/promotion and portable installation share the same
  frontmatter-name check. Missing, duplicate, or mismatched names are rejected.
- Gates start in a separate process group on POSIX and kill that group on timeout.
  Regression cases include a running wrapper and an exited wrapper whose child
  retains output pipes. Windows uses `taskkill /T /F`; Windows behavior remains
  unverified. Processes deliberately escaping their group are outside this bound.
- Native installer status now includes portable skill additions and updates.

Scoped validation: **144 tests passed in 37.20 seconds** across
`tests/test_hooks.py`, `tests/test_learning.py`, `tests/test_native.py`, and
`tests/test_portable.py`. Ruff on changed scripts/tests and `git diff --check`
passed. An independent read-only code review found no blocking regression.
The full suite was not run.

## Local evidence

The operator's smoke repositories and raw transcripts are under
`/home/ubuntu/kit-host-smoke/`. They are outside this repository and are not
published; authentication diagnostics can contain sensitive metadata.

Relevant evidence files under its `evidence/` directory:

- `codex-config-check.jsonl`: named role discovery and actual guard denial.
- `codex-stop.jsonl`: automatic failing gate and resumed model report.
- `codex-fix-review.jsonl`: failing gate, correction, passing gate, reviewer phase.
- `codex-reviewer-evidence.json`: selected native spawn fields from the local
  session record, confirming the custom agent type without copying prompt content.
- `grok-inspect-trusted.txt`: project discovery after trust.
- `grok-manual-fail.txt`: failing manual gate.

The earlier `codex-discovery` and `codex-hooks` logs used
`--ignore-user-config`; retain them as diagnostic evidence of that limitation.

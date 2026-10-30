# claude-kit

One shared source for the Claude Code setup used across my repos (ML_analytics, Grok_Bot, and new builds). The repo is a **plugin marketplace** named `vtech-kit`. Each project turns its plugins on with a few lines in its own `.claude/settings.json`, so a change made here reaches every repo on its next update, without copying files around.

| Plugin | What it gives every repo that enables it |
|---|---|
| `kit` | One prompt is enough: `/kit:deliver` settles the approach, sizes the task and routes it, and a SessionStart hook tells Claude to use it. `/kit:deliberate` runs the design stage against `design-critic`. Plus hooks that lint and test what Claude changed before it can finish, guards on destructive commands, `reviewer` / `test-runner` / `security-reviewer` subagents, and the skills `/kit:verify`, `/kit:scale-out`, `/kit:spec`, `/kit:fix-issue`, `/kit:adopt` |
| `quant` | `causality-reviewer` (look-ahead leakage) and `query-reviewer` (SQL/TimescaleDB) subagents |

## What lives where

| Kind of thing | Where it goes | Why |
|---|---|---|
| Reusable hooks, agents, Claude-only skills | this repo | Edit once, every repo gets it |
| Project rules every agent should follow (Claude, Copilot, Codex, Grok) | the project's `AGENTS.md` | Vendor-neutral |
| Claude-specific project notes | the project's `CLAUDE.md`, which imports `@AGENTS.md` | When both files exist, Claude Code reads only `CLAUDE.md`. Without the import it never sees `AGENTS.md` |
| Skills shared with Copilot | the project's `.github/skills/`, symlinked into `.claude/skills/` | One copy serves both tools. Claude Code follows skill symlinks |
| Permissions, plugin switches | the project's `.claude/settings.json` | Repo-specific |
| Verify and guard settings (interpreter, lint args, test dirs, guards) | the project's `.claude/kit.json` | Repo-specific input to the shared hooks |

## Use it in a repo

1. Add this to the repo's `.claude/settings.json` (merge with what's there):

   ```json
   {
     "extraKnownMarketplaces": {
       "vtech-kit": { "source": { "source": "github", "repo": "vbasin/claude-kit" } }
     },
     "enabledPlugins": { "kit@vtech-kit": true, "quant@vtech-kit": true }
   }
   ```

2. Add `.claude/kit.json`. Start from [`plugins/kit/templates/.claude/kit.json`](plugins/kit/templates/.claude/kit.json). Without it the guards still work, but nothing is linted or tested.
3. Start `claude` in the repo and accept the folder-trust prompt. Claude Code registers the marketplace and loads both plugins. Check with `/plugin`.

Or open Claude Code in the new repo after step 1 and run `/kit:adopt`, which walks through all of it.

**Private repo access:** if the marketplace is private, the machine running Claude Code needs git credentials for it. On the OCI VM, `gh auth login` followed by `gh auth setup-git` is enough. If the VM has no GitHub SSH key, also set `CLAUDE_CODE_PLUGIN_PREFER_HTTPS=1`.

## Updating

Plugins here have **no `version` field on purpose**, so installs track the latest commit on `main`. To pull changes into a machine:

```
/plugin marketplace update vtech-kit
```

To make updates automatic, open `/plugin` → **Marketplaces** → `vtech-kit` → **Enable auto-update**. If you ever need to hold a repo on a known-good state, add `"version": "x.y.z"` to the plugin's `plugin.json`. Users then only move when you bump it.

## One prompt, not a routing decision

The point of the setup is that the user describes the outcome and Claude works out the scale. Two pieces do that:

- **`/kit:deliver`** holds the protocol: frame the goal and its done-check, settle the approach, size the work, choose between this session, parallel subagents, `/batch` and an `ultracode:` workflow, brief the workers, run the repo's gates, run the matching reviewers, then report. It also names the harness gaps it hits (a missing scope, a rule worth writing) instead of silently widening the job.
- **`/kit:deliberate`** is the design stage `deliver` hands off to whenever the shape of the work is not obvious. It looks up what already exists, writes the criteria *before* any candidate so the first idea can't be rationalised, generates two to four designs that differ in structure rather than detail, has `kit:design-critic` attack them from a fresh context, revises, and attacks again until no surviving objection changes the pick or three rounds are up. Then it records the decision, the rejected options and what would reverse it.
- **`kit:design-critic`** is that adversary. It checks the *field* and the *criteria* before the candidates, because a missing candidate matters more than a flaw in a present one, and it has to pick one and name the fact that would change its mind.
- **`session_policy.py`** prints that instruction into every session, so Claude reaches for `deliver` on its own. The design is never the user's to supply: requirements are theirs, the approach is Claude's.

A repo points `deliver` at its own gates and reviewers in `.claude/kit.json`:

```json
"routing": {
  "note": "Work happens on dated branches; AGENTS.md governs.",
  "decisions": "docs/decisions",
  "gates": [ { "paths": ["src/acquisition/**"], "command": "make test-acquisition" } ],
  "reviewers": [ { "paths": ["src/features/**", "src/labels/**"], "agent": "quant:causality-reviewer" } ]
}
```

`decisions` is where `deliberate` writes its decision logs. Unset, it falls back to the repo's own convention, then to `.claude/decisions/`.

`"routing": { "enabled": false }` turns the session policy off for a repo that doesn't want it.

## How verification works

`kit` runs five small stdlib-only Python hooks (`plugins/kit/scripts/`):

| Hook | Script | Does |
|---|---|---|
| SessionStart | `session_start.py` | Records which files were already dirty, so only this session's changes are checked |
| SessionStart | `session_policy.py` | Prints the routing policy into the session, so one prompt reaches both the right approach and the right scale of work |
| PreToolUse (Bash) | `bash_guard.py` | Asks before `DROP`/`TRUNCATE`/`DELETE` without `WHERE`/chunk operations, before full-suite pytest runs (opt-in), and before repo-specific patterns |
| PostToolUse (Edit/Write) | `post_edit.py` | Remembers the edited file and lints it at once |
| Stop | `stop_verify.py` | Lints the session's changed `.py` files and runs all discovered tests for source changes, and directly related tests for test-only changes, as explicit paths. On failure it sends the output back so Claude keeps working. If Claude stops again with the same failure, it lets the stop through with a notice, so a pre-existing failure can't trap a session |

Without explicit verification gates, source changes run all configured Python test files; test-only changes use related files up to `tests.max_files`, with capped or excluded files reported as incomplete. Deleted files are included. Each run starts with an empty bytecode cache, and an interpreter without pytest counts as a failure rather than a pass. A repo can add guard patterns in `.claude/kit.json`:

```json
"guards": { "patterns": [ { "regex": "databento.*(download|get_range)", "reason": "Check the data cost first", "decision": "ask" } ] }
```

## Does the kit help?

`plugins/kit/evals/` is an eleven-case `claude plugin eval` suite. Every case runs with the
plugin and again with no plugin at all, so the number it reports is **Δ** — what the kit
contributed, not what the model would have done anyway.

```bash
claude plugin eval ./plugins/kit --ablation with-without
```

| Case | Claim it can falsify |
|---|---|
| `task-first` | A suitable existing tool completes the user's task before optional kit improvements |
| `capability-required` | A missing task-critical capability is obtained or built during the task |
| `reusable-capability` | A repeated gap leads to a tested reusable candidate |
| `design-not-handed-back` | The design is Claude's to settle, by comparing rivals against stated criteria |
| `obvious-fix-stays-cheap` | The kit doesn't charge design ceremony for a one-line fix |
| `duplication-is-a-defect` | Duplication and dead config are reportable defects, named at their location |
| `sweep-gets-fanned-out` | Independent work that can't be scripted gets fanned out, and one route is chosen |
| `prior-decision-is-reused` | A decision already on record is reused, not re-derived, while its reversal conditions hold |
| `reversed-decision-reopens` | The same log with a reversal condition now true: the decision reopens from the recorded candidates, not from scratch |
| `promotion-is-offered-not-taken` | A generic addition is offered to the kit with its cost; a repo-specific one stays local |
| `delivery-applies-the-floor` | A task-shaped request gets the delivery protocol, and the fix lands at the cause rather than at the line pointed at |

`obvious-fix-stays-cheap` is the case the kit can lose: its pass condition is Δ near zero,
because every always-on token the kit adds is paid on trivial prompts too. A suite made
only of cases the kit is designed to win would never report that.

The suite spends plan usage — 11 cases × 3 runs × 2 arms is 66 agent runs — so it is run by
hand, not in CI, which would need an `ANTHROPIC_API_KEY` a subscription doesn't provide.
`python -m pytest tests/test_evals.py` checks the suite's schema for free.
[`plugins/kit/evals/README.md`](plugins/kit/evals/README.md) covers the dials and how to
read a number you can trust; the reasoning is in
[docs/decisions/](docs/decisions/2026-10-29-measure-the-kit-with-plugin-evals.md).

## Develop

```bash
pip install pytest ruff
python -m pytest tests          # hook tests + eval-suite schema (no network, no model calls)
claude plugin validate .        # marketplace + both plugins
claude --plugin-dir ./plugins/kit   # try local edits without pushing
```

CI runs both on every PR (`.github/workflows/validate.yml`). It does not run the eval
suite: that needs model credentials in the environment, and a Claude subscription
isn't one.

## Background

The research and plan behind this setup are in [docs/PLAN.md](docs/PLAN.md).

## Language-neutral verification gates

For projects with a trusted, scoped test target, enable `verification` in `.claude/kit.json`:

```json
"verification": {
  "enabled": true,
  "gates": [
    {"name": "web-tests", "paths": ["web/**"], "argv": ["npm", "test", "--", "--run"], "timeout_s": 300},
    {"name": "api-tests", "paths": ["api/**"], "argv": ["make", "test-api"], "timeout_s": 300}
  ]
}
```

Every changed path must match a gate. Commands run as argument arrays without a shell;
`cwd` is optional and must remain within the repository. Gates replace automatic pytest
selection when enabled; Python lint settings still apply. Gate coverage is a repo contract:
include affected integration tests and shared configuration paths. Test commands execute
with the user's privileges. The manual verifier and Stop hook use the same gate runner.

## Learning reusable skills

`/kit:improve` turns a recurring gap into a candidate skill and evaluates it before
promotion. Candidates contain `candidate.json` (name, purpose, applies_when, not_for,
evidence) and `skill/SKILL.md`. Prepare a trusted, separate JSON suite such as:

```json
{"cases": [
  {"name": "improvement", "fixture": "fixtures/improvement", "argv": ["python3", "check.py"]},
  {"name": "regression", "fixture": "fixtures/regression", "argv": ["python3", "check.py"]}
]}
```

Each check runs twice in fresh copies of its fixture: `KIT_CANDIDATE_DIR` is empty in the
baseline arm and points to the candidate skill in the other arm. Exit 0 means the check
passed. The suite must observe an improvement and preserve at least one baseline success without candidate failures. `learning.py
promote` reruns the suite and refuses to overwrite an existing skill. Use only trusted
suite commands; they execute with your privileges. Model-dependent behavioral evals and
independent review remain necessary before releasing a shared skill.

## Task-first workflow for Claude, Codex, and Grok

Claude's `/kit:deliver` reads the shared portable protocol. To install that same protocol
and its supporting scripts into a target repository for Codex, Grok Build, or Claude Code:

```bash
python plugins/kit/scripts/install_portable.py --repo /path/to/project --host codex
python plugins/kit/scripts/install_portable.py --repo /path/to/project --host grok
python plugins/kit/scripts/install_portable.py --repo /path/to/project --host claude
```

Codex discovers the copy in `.agents/skills/kit-deliver`, Grok Build discovers its copy in
`.grok/skills/kit-deliver`, and Claude Code can discover its copy in
`.claude/skills/kit-deliver`. The installer leaves pre-existing unmanaged or modified skills
alone; an unchanged managed installation is updated safely. Host trust, skill activation,
hooks, permissions, available tools, and subagent behavior differ. Explicitly invoke the
`kit-deliver` skill if it is not selected, and use a sequential fallback when a host lacks a
capability. A bare model API needs a tool-capable host. No model parity is implied.

For host-neutral repository checks, place the existing gate configuration in
`.kit/kit.json`; `.claude/kit.json` takes precedence if both exist. Run
`python <installed-skill>/scripts/stop_verify.py --manual <changed-file>` from the target
repo. These are explicit commands on Codex and Grok; Claude's native hooks remain separate.

For a necessary missing capability, search existing tools, research current sources, then
adapt or build what is needed to finish the task. Record optional improvements without
secrets using `<installed-skill>/scripts/backlog.py` and evaluate them **after** delivery.
The default backlog lives in `~/.vtech-kit/learning.jsonl`, outside the target project.
Use `backlog.py --help` to add, list, and resolve entries. Candidate evaluation and
promotion use the bundled `scripts/learning.py`; a trusted independent suite is required.
A validated host-neutral skill marked with `.kit-portable` in `plugins/kit/skills` is
installed for Codex and Grok on the next installer run and is discoverable by the Claude
plugin. Skills removed from the source are not automatically deleted from existing repos;
review and remove outdated copies manually.

For numeric comparisons, run `python <installed-skill>/scripts/score.py
examples/seo-comparison.json`. Each criterion declares direction, bounds, weight and an
optional hard threshold; every option needs a value and evidence for each criterion. An
unknown value is incomplete, not zero. Weights and bounds are assumptions: scores describe
those assumptions and cannot prove global optimality. The SEO file contains synthetic
example data, not actual site or ranking results.

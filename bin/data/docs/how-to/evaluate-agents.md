# Evaluate agents

[Documentation](../index.md) · How-to

The agent evaluation harness measures whether an agent completes realistic Forge tasks, and at what cost. Each task gives an agent a prompt in a fresh fixture workspace and then verifies the end state with deterministic checks: files, frontmatter, structured data, command results and the final answer. Run it with the `reference` driver to prove the tasks are valid, and with the opt-in `claude` driver to measure Claude Code.

Run the commands from the Forge project directory `src/the-forge` after `npm run build`, because every task workspace copies the built distribution from the workspace `bin/`.

## Validate the tasks with the reference driver

```sh
npm run eval
npm run eval -- --task recover-stale-revision --task links-rename-note
npm run eval -- --category error-recovery
```

The reference driver (the default) replays each task's reference command sequence and requires four things: at least one check fails on the prepared fixture; every reference step succeeds, or fails with the code it expects; every text an answer check requires (`contains` and `items`) occurs in the output of the reference steps, ignoring case, so a wrong reference answer fails instead of passing against itself; and afterwards every check passes, with answer checks matched against the task's reference answer. The first rule proves little for a question task: its answer check always fails before the run, because there is no answer yet, so its state checks may all pass on the prepared fixture. The reference output rule is what keeps such an answer honest. It prints a JSON summary and exits 1 when any task fails. `npm run check` runs the same driver over every task in `tests/evals/reference.e2e.test.ts`, which also requires that tasks use only commands the built executable registers.

## Measure Claude Code

```sh
npm run eval -- --driver claude
npm run eval -- --driver claude --task bases-add-view --repeat 3 --model sonnet
```

The `claude` driver runs `claude -p` headless in each task's workspace with `--output-format stream-json`, `--permission-mode dontAsk`, `--setting-sources project` and `--strict-mcp-config --mcp-config '{"mcpServers":{}}'`, so no MCP server from your user or project configuration loads. `setup` has already installed the Forge skills into `.claude/skills` and `.agents/skills` and written `AGENTS.md`, as in a real installation. The agent may run exactly one shell command, a guarded Forge wrapper, plus the read-only native tools `Read`, `Glob` and `Grep`; pass `--allowed-tool <rule>` (repeatable) to replace the native tools, for example to compare against native `Edit`. The prompt tells the agent to use the wrapper wherever the skills say `node bin/forge.js`.

### Isolation and residual risk

An agent that may run `node bin/forge.js` with any arguments can leave its workspace: `--root <any folder>` writes elsewhere, and `claude hooks add --scope user` or `claude plugins install` change your own Claude Code configuration. Each attempt is therefore hardened (`scripts/eval/guard.mjs`):

- Every evaluation workspace disables the core plugins that act on the host, `claude`, `connector` and `connector-azure-devops`, in its `bin/config.json`; no task needs them. The reference driver runs with the same configuration.
- The only allowed shell command is `node <guard folder>/forge.mjs`. The wrapper lives in a temporary folder outside the workspace, so Forge writes cannot replace it. It runs `node bin/forge.js --root <workspace>` and refuses `--root`, `--claude-dir`, `--claude-bin` and `--scope user` with the failure code `EVAL_REFUSED` (exit 2).
- The wrapper runs Forge with `HOME`, `USERPROFILE`, `XDG_CONFIG_HOME`, `XDG_DATA_HOME`, `XDG_CACHE_HOME`, `XDG_STATE_HOME` and `CLAUDE_CONFIG_DIR` pointing into the guard folder, so anything that resolves a user-level location stays inside it. Forge receives no other environment variable except `PATH`, the locale (`LANG`, `LANGUAGE`, `LC_*`), `TZ`, `TERM`, the temporary folders and the Windows system variables Node needs: tokens such as `ANTHROPIC_API_KEY` or `AZURE_DEVOPS_EXT_PAT` and `NODE_OPTIONS` never reach it.
- Each attempt checks the transcript's `system` `init` event: when it is missing, or reports an MCP server or a Claude Code plugin, the attempt fails with the names in its `error`.
- Before every call the wrapper compares a digest of the workspace's `bin/` (the executable, `config.json` and `plugins/`; templates, documentation and the project selection may change) with the one taken after setup, and refuses to run once it differs. An agent that writes `bin/config.json` or a plugin through Forge therefore cannot get that code loaded.

The Claude Code process itself keeps your environment, because its authentication lives in your home directory or keychain; isolating it with a different `HOME` or `CLAUDE_CONFIG_DIR` would log it out. Residual risk: the native `Read`, `Glob` and `Grep` tools can read any file your account can read, and `dontAsk` relies on Claude Code's own permission matching for compound commands and substitutions. Run the claude driver in a disposable container or sandbox, without credentials beyond the Claude Code login, when the tasks or the model under test are not trusted.

| Option | Default | Meaning |
| --- | --- | --- |
| `--repeat k` | 1 | Attempts per task; `passAllRate` is pass^k, the share of tasks that passed every attempt |
| `--model id` | Claude Code's default | Model for the session |
| `--max-turns n` | 30 | Turn limit per attempt |
| `--timeout seconds` | 600 | Time limit per attempt |
| `--claude path` | `claude` | The Claude Code executable |
| `--results directory` | `evals/results` | Where the results file is written |

An attempt that reaches `--timeout` fails with `timedOut: true` and an error naming the timeout: the driver starts Claude Code in its own process group and ends the whole group (SIGTERM, then SIGKILL after two seconds; `taskkill /T /F` on Windows), so tool processes the agent started never outlive the attempt or its deleted workspace. When Claude Code exits, the driver also ends what is left of its group. Because the group is Claude Code's own, Ctrl+C in the terminal reaches only the driver: on SIGINT or SIGTERM it forwards the signal to the running group, ends the group with SIGKILL if it still runs two seconds later and starts no further attempt. The interrupted attempt fails with `interrupted: true` and no evaluated checks; the driver removes its temporary workspace and guard folders, writes the results file with the attempts so far (the summary names the signal in `interrupted` and counts `attempts` and `notStarted`) and then exits with that signal. A second Ctrl+C ends the driver at once, without that cleanup. On Windows there are no process groups: `taskkill /T` walks the tree from Claude Code while it runs, so cleanup after Claude Code exited is skipped (its id may already name another process), and a tool process it left running can outlive the attempt. Error messages from Claude Code are reported with the values of secret-named environment variables replaced by `***` before they are shortened to 2,000 characters.

The driver runs attempts one after another and writes `evals/results/<timestamp>.json` (or into `--results <directory>`), which Git ignores: a summary with `passRate`, `passAllRate`, turns, cost, input, output and cache tokens, tool calls split into Forge CLI calls, other shell commands and native tools, the number of Forge error codes the agent saw, and `interrupted` (the signal that ended the run, or null); per task the attempts and passes; and per attempt the check results and transcript metrics. Review failed checks and repeated error codes before changing a skill, a hint or a command.

Like the reference driver, the claude driver exits 1 when any attempt fails, after writing its results. The summary also counts `timedOut` attempts. The claude driver needs a locally installed and authenticated `claude`. It never runs in CI (it refuses when `CI` is set), and the repository holds no API keys.

## Write a task

Tasks live in `evals/tasks/<id>.yaml`; fixtures are folders under `evals/fixtures/` that are copied to the workspace root. The `vault` fixture is a small trip-planning vault with linked notes, a Canvas, a Base, a JSON configuration file, a workspace template and the managed project `projects/demo`.

```yaml
id: recover-stale-revision
title: Recover from a stale revision without losing a concurrent change
category: error-recovery
prompt: |
  Earlier you read Projects/Alpha.md at revision {{initial:Projects/Alpha.md}}. ...
fixture: vault
setup:
  - [edit, Projects/Alpha.md, --if-match, "{{initial:Projects/Alpha.md}}", --find, "- GPS accuracy in valleys.", --replace, "- GPS accuracy in valleys and canyons."]
reference:
  - run: [edit, Projects/Alpha.md, --if-match, "{{initial:Projects/Alpha.md}}", --find, "1. Prototype the share link.", --replace, "1. Prototype the share link with expiry."]
    expect: { code: CONFLICT }
  - [read, Projects/Alpha.md]
  - [edit, Projects/Alpha.md, --if-match, "{{revision:Projects/Alpha.md}}", --find, "1. Prototype the share link.", --replace, "1. Prototype the share link with expiry."]
checks:
  - file: Projects/Alpha.md
    contains: ["1. Prototype the share link with expiry.\n", "- GPS accuracy in valleys and canyons.\n"]
```

| Field | Meaning |
| --- | --- |
| `id`, `title`, `category` | The id equals the file name. Categories: `reading`, `searching`, `linking`, `editing`, `canvas-bases`, `backlog`, `generation`, `projects`, `error-recovery` |
| `prompt` | What the agent receives, in the user's words; never name the reference commands |
| `fixture` | A folder under `evals/fixtures` |
| `setup` | Forge commands run after `setup` and before the agent starts, for example another agent's concurrent change |
| `reference` | The command sequence that solves the task; a step is an argument list, or `{run, expect: {code}}` for an expected failure |
| `answer` | The reference final answer; required exactly when an `answer` check exists |
| `checks` | Deterministic assertions on the end state |

Arguments after `node bin/forge.js` omit `--root` and `--json`. In prompts and arguments, `{{revision:path}}` expands to the file's current SHA-256 and `{{initial:path}}` to its revision in the fixture, before setup.

| Check | Passes when |
| --- | --- |
| `{file, exists: false}` | The file does not exist |
| `{file, contains, notContains}` | The file exists and contains every listed text and none of the excluded ones |
| `{file, frontmatter}` | The YAML frontmatter contains the listed properties with equal values (deeply; other properties may exist) |
| `{file, data: {pointer, equals \| contains \| length}}` | The JSON Pointer into the parsed file (JSON for `.json` and `.canvas`, YAML for `.base` and `.yaml`) equals a value, contains a substring or a matching array element, or has a length |
| `{command, data?}` | The Forge command succeeds, and its `data` meets the pointer assertion |
| `{command, code}` | The Forge command fails with that code |
| `{unchanged: path}` | The file's bytes equal those after setup |
| `{answer: {contains, notContains}}` | The final answer mentions every `contains` text and none of the `notContains` texts, ignoring case |
| `{answer: {items, ignore?}}` | An exact set for list questions: the final answer names every listed path and no other file path of the fixture (outside hidden folders), ignoring case, except the `ignore` paths such as the note the question is about. An answer that lists every path fails |

Prefer state checks over answer checks, use `items` for questions whose answer is a list of notes, check that unrelated content survived an edit, and add a check that fails on the prepared fixture. Validate the format with `npm run eval -- --task <id>`; the task schema is `taskSchema` in `scripts/eval/tasks.mjs`.

## Coverage

The 35 tasks cover reading, search, links and link-preserving moves and deletes, literal edits, precise edits (a section rewrite, a block replacement that keeps its `^id`, and several replacements in one `--edits` list), an atomic `apply` plan that sets a property, moves a note with link rewriting, edits it and moves another note to the trash, a `vault check --strict` repair loop, properties, text files, Canvas, Bases, backlog planning, document and code generation, independent webview scaffolding, offline browser-plan validation and previews, project scope, dry runs, and recovery from `CONFLICT`, `AMBIGUOUS_EDIT` and `NOT_FOUND`. Keep the suite at most 35 tasks so the reference run stays affordable inside `npm run check`; replace a task rather than growing the suite past that.

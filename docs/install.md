# Install

ultrathink runs from one checkout of this repository. Each host (the coding agent you type into: Claude Code, Grok Build, Hermes Agent, Muse Code, Omp or Prime Agent) loads it through a small entry point, and every host calls the same TypeScript engine. This page covers installing it on each host and checking that it works. It also covers `scripts/setup.ts`, the shared MCP gateway and choosing the planning engine. To upgrade, move or remove an install, see [Upgrade and move](how-to/upgrade-and-move.md) and [Uninstall](how-to/uninstall.md).

In the commands below, `<clone>` is the absolute path of your checkout. Paths written as `${NAME:-default}` use the environment variable when you set it, and the default otherwise.

- [Platforms](#platforms)
- [Prerequisites](#prerequisites)
- [Claude Code](#claude-code)
- [Grok Build](#grok-build)
- [Hermes Agent](#hermes-agent)
- [Muse Code](#muse-code)
- [Omp](#omp)
- [`scripts/setup.ts` reference](#scriptssetupts-reference)
- [Shared MCP gateway](#shared-mcp-gateway)
- [Engine selection](#engine-selection)

## Platforms

ultrathink runs on Linux and macOS. On Windows, run it and your host inside WSL; native Windows is not supported. CI runs the test suite on Linux only; macOS is supported but not tested in CI.

## Tested with

| Component | Version |
|---|---|
| Claude Code | 2.1.278 |
| Grok Build | 1.0.41 |
| Hermes Agent | v0.21.4 |
| Muse Code | 1.4.0 |
| Omp | 18.3.1 (native planning: 18.8.0) |
| Prime Agent | 0.9.8 |
| Bun | 1.4.0 (1.2 or later required) |
| Greptile CLI (optional, for ship) | 3.4.1 |

## Prerequisites

| Requirement | Version | Needed for |
|---|---|---|
| [Bun](https://bun.sh) | 1.2 or later | Every host. The hooks, the engine and the CLIs run on Bun. |
| Python | 3.10 or later | Hermes Agent only, which runs the plugin in its own Python. |
| `git` | any | Cloning the repository. |
| `claude` CLI, logged in | 2.1.278 or later (the tested version) | The Claude engine: the default on Claude Code and Hermes, Omp's ship done check and Teachable Moments distiller under `auto`, and Claude in Grok's place when you set `grok.fallbackToClaude` or `grok.enabled: false` (see [Engine selection](#engine-selection)). Omp's own planning doesn't need it. The engine passes `claude -p` flags that older CLIs reject, and then every plan falls back. |

1. **Bun.** Hosts often start hooks with a short `PATH`, so they launch Bun through `bin/run-bun`. It looks for Bun in this order and uses the first it finds:

   1. `$BUN`
   2. `bun` on `PATH`
   3. `$BUN_INSTALL/bin/bun`
   4. `~/.bun/bin/bun`
   5. `/usr/local/bin/bun`
   6. `/opt/homebrew/bin/bun`
   7. `~/.local/share/*/bun/bin/bun`

   If Bun is in none of these places, `bin/run-bun` prints one line to stderr, `ultrathink: bun not found. Install Bun 1.2 or later (https://bun.sh) or set BUN=/path/to/bun`. What happens next depends on the caller:

   - **Hooks** exit 0, so your prompt still goes through, just unplanned. Nothing blocks the host.
   - **The CLIs** (`bin/ultrathink`, `bin/ultrathink-mcp`, `bin/ultrathink-ship`) exit 127, the shell's "command not found" status, so scripts notice the failure.

2. **A clone of the repository.**

   ```sh
   git clone https://github.com/swcstudiospace/claude-ultrathink.git <clone>
   ```

   ultrathink has no runtime dependencies, so `bun install` is not needed to run it. It only installs type definitions for development. (If you plan to use Muse, see the note on symlinks in [Muse Code](#muse-code).) A Claude Code install from the GitHub marketplace does not need a clone. The other hosts and the MCP gateway do. Keep the clone where it is: several hosts store its path. If you move it later, follow [Upgrade and move](how-to/upgrade-and-move.md#move-the-clone-to-another-directory).

3. **An engine login.** Planning runs its own model calls, apart from the host's work.
   - Claude (the default on Claude Code and Hermes): the `claude` CLI must be on `PATH` and logged in. The engine runs `claude -p` headless.
   - Grok (the default on Grok Build): run `grok login`, unless you use the `shunt` transport. See [Engine selection](#engine-selection).
   - Muse (the default on Muse Code): the `muse` CLI must be on `PATH` and logged in. The engine runs `muse exec` headless.
   - Omp: nothing extra. Under `auto`, Omp plans on the session's own model with Omp's own provider and login. See [Omp](#omp).

Optional:

| Tool | Needed for |
|---|---|
| `gh`, logged in | [Ship](ship.md) (opt-in): pushing, opening and merging the PR |
| Greptile CLI (`greptile login`) | Ship's CLI review mode |
| Notion, Linear, Greptile credentials | [Tracking](tracking.md) and ship, through the [shared MCP gateway](#shared-mcp-gateway) |
| A Jev key: a Vercel AI Gateway API key (`bin/ultrathink-mcp auth set-key vercel --stdin`, or `AI_GATEWAY_API_KEY`) or an OpenRouter API key (`bin/ultrathink-mcp auth set-key openrouter --stdin`, or `OPENROUTER_API_KEY`) | [Jev decisions](how-to/use-jev-decisions.md) (always on once a key exists): it is stored in the same credential store, but `vercel` and `openrouter` are not MCP servers and are never registered in a host |
| A Hindsight API key (`bin/ultrathink-mcp auth set-key hindsight --stdin`, or `HINDSIGHT_API_KEY` / `HINDSIGHT_API_TOKEN`) | [Hindsight](how-to/connect-hindsight.md) (opt-in, `hindsight.enabled`). Not an MCP server. |
| A RAGFlow API key (`bin/ultrathink-mcp auth set-key ragflow --stdin`, or `RAGFLOW_API_KEY`) | [RAGFlow](how-to/connect-ragflow.md) (opt-in, `ragflow.enabled`). Not an MCP server. |

A fresh install plans prompts and learns from finished turns. Linear and Notion tracking, ship, the Agent Substrate brief, Hindsight, RAGFlow and the Tailscale OAuth callback are all off until you configure them. Teachable Moments is on by default: it keeps lessons, recalls them and installs skills on the local machine, and distills each qualifying finished turn with one extra call to the planning engine that carries a redacted excerpt of the session, tool results included (see [Privacy](privacy.md#planning-engine-lesson-distillation), and [Use Teachable Moments](how-to/use-teachable-moments.md#turn-it-off-again) to turn it off). See [Configuration](configuration.md) and [Tracking](tracking.md).

Each host keeps its own state directory. Planning never writes `.planning/` into your working directory. Teachable Moments state is `<state directory>/teach/`, never `<cwd>/.planning`.

| Host | State directory | `ULTRATHINK_HOST` id |
|---|---|---|
| Claude Code | `${CLAUDE_CONFIG_DIR:-~/.claude}/ultrathink` | `claude-code` |
| Grok Build | `$GROK_PLUGIN_DATA/ultrathink` if set, otherwise `${GROK_HOME:-~/.grok}/plugin-data/ultrathink` | `grok-build` |
| Hermes Agent | `${HERMES_HOME:-~/.hermes}/ultrathink`; with an active Hermes profile, `ultrathink` in that profile's directory (`${HERMES_HOME:-~/.hermes}/profiles/<name>`) | `hermes` |
| Muse Code | `${XDG_CONFIG_HOME:-~/.config}/muse/ultrathink` | `muse` |
| Omp | `${PI_CODING_AGENT_DIR:-~/.omp/agent}/ultrathink` | `omp` |

`bin/ultrathink` works on the Claude Code state unless it detects another host. From a plain shell, set `ULTRATHINK_HOST` to read or change another host's state. For example:

```sh
ULTRATHINK_HOST=hermes <clone>/bin/ultrathink status
```

## Claude Code

Claude Code loads ultrathink as a plugin: `.claude-plugin/` holds the marketplace and plugin manifests, and `hooks/hooks.json` holds the hooks.

### Install

In a Claude Code session:

```text
/plugin marketplace add swcstudiospace/claude-ultrathink
/plugin install ultrathink@ultrathink
```

Or from a shell:

```sh
claude plugin marketplace add swcstudiospace/claude-ultrathink
claude plugin install ultrathink@ultrathink
```

`claude plugin install` installs at user scope by default. Pass `--scope project` or `--scope local` to change that.

**Development install from a clone.** Add the checkout as a local-path marketplace. It has the same marketplace name, `ultrathink`:

```sh
claude plugin validate <clone>
claude plugin marketplace add <clone>
claude plugin install ultrathink@ultrathink
```

`bun scripts/setup.ts apply` does the same two `marketplace add` and `install` steps, and more. See the [`scripts/setup.ts` reference](#scriptssetupts-reference).

Start a new Claude Code session after installing.

### Verify

1. Run `/ultrathink-status`. The plugin also lists it as `/ultrathink:ultrathink-status`. The prompt hook answers before any model turn and shows the engine (for example `Engine: claude:claude-haiku-5-5`), the engine request (`Engine request: auto (config) · concurrency 3`), the tracking state and the state directory. From a shell, `<clone>/bin/ultrathink status` prints the same thing.
2. Send a non-trivial prompt, such as a one-line feature request. The transcript shows a summary line that starts with `Prompt Uplift ·`, and the agent invokes `ultrathink-kickoff` before it does other work.

Verified live on Claude Code 2.1.278: `/ultrathink-status` and `/ultrathink-quick` in `claude -p`. Headless, the status reply appears as "blocked by hook" text. A quick message was answered and no plan was written.

### Update and uninstall

See [Upgrade and move](how-to/upgrade-and-move.md#upgrade) and [Uninstall](how-to/uninstall.md#claude-code).

## Grok Build

Grok Build uses the plugin directory for skills and commands. It finds the plugin's `hooks/hooks.json` but does not dispatch plugin hooks, so `bun scripts/setup.ts apply` installs a global hook file, `${GROK_HOME:-~/.grok}/hooks/ultrathink.json`. That file is a copy of `hooks/hooks.json` with absolute paths, `ULTRATHINK_HOST=grok-build` on every hook, and a 600 s timeout on the prompt hook in place of Grok's 30 s default. Because the paths are absolute, run `apply` again after moving the clone.

Grok also discards hook stdout, so the plan cannot be injected into the turn directly. Instead, the hook writes the plan to `last-plan.json` in the Grok state directory (`$GROK_PLUGIN_DATA/ultrathink/` if set, otherwise `${GROK_HOME:-~/.grok}/plugin-data/ultrathink/`), and `apply` installs the rule `${GROK_HOME:-~/.grok}/rules/ultrathink.md`. The rule tells the model to read that file before acting. `last-plan.json` exists only for a prompt that was planned. The hook deletes it on every prompt it does not plan (`/ultrathink-quick`, control commands, skipped or trivial prompts, planning turned off), so the model never picks up an older plan.

`apply` never overwrites the rule. If the rule file is missing, it writes the packaged rule from `hosts/grok/ultrathink.md`. If the file exists, it replaces only the block between `<!-- ultrathink:start -->` and `<!-- ultrathink:end -->`, or appends the block when there is none. Your own text in that file is kept.

### Install

```sh
mkdir -p ${GROK_HOME:-~/.grok}/plugins
ln -sfn <clone> ${GROK_HOME:-~/.grok}/plugins/ultrathink
grok plugin enable ultrathink
bun <clone>/scripts/setup.ts apply
```

Grok keeps a plugin disabled until you enable it, so without `grok plugin enable` the skills and commands don't load.

`apply` installs the Grok rule and hook file first. It also sets up Claude Code, which the [`scripts/setup.ts` reference](#scriptssetupts-reference) describes. If the `claude` CLI is not installed, it skips the Claude Code steps and prints a notice, so a machine with only Grok Build can run it.

### Verify

1. `grok plugin list` shows `ultrathink` as enabled.
2. Run `bun <clone>/scripts/setup.ts status`. It should print `Grok rule: installed (…/rules/ultrathink.md)` and `Grok hooks: installed (…/hooks/ultrathink.json)`. The rule counts as installed only when it contains the `<!-- ultrathink:start -->` … `<!-- ultrathink:end -->` block.
3. Start Grok and run `/ultrathink-status`. The prompt hook blocks the command and shows the state.
4. Send a non-trivial prompt. `last-plan.json` should appear in the Grok state directory, and the model should read the plan and invoke `ultrathink-plan`, then `ultrathink-kickoff`. After a `/ultrathink-quick` message or a control command, the file is gone.

Verified live on Grok Build 1.0.41: `/ultrathink-status` and `/ultrathink-quick` in `grok -p`. A quick message was answered. In headless mode a blocked control command prints nothing, so check status in the interactive UI or with `ULTRATHINK_HOST=grok-build <clone>/bin/ultrathink status`.

### Update and uninstall

See [Upgrade and move](how-to/upgrade-and-move.md#upgrade) and [Uninstall](how-to/uninstall.md#grok-build). After moving the clone, run `bun <new clone>/scripts/setup.ts apply` and re-point the symlink.

## Hermes Agent

Hermes loads `hosts/hermes`, a Python plugin with `plugin.yaml` and `register()`. It needs Python 3.10 or later. Its `pre_llm_call` hook sends the prompt to `hooks/engine.ts` through `bin/run-bun` (or through `$BUN` when set) and returns the plan as context. Hermes gives the hook no working directory, so the planner takes the turn directory from the environment: local CLI turns use the process directory (the launch directory; `--in` changes it first), while gateway, cron, TUI and other turns use `TERMINAL_CWD` (bridged from the profile's `terminal.cwd`); each falls back to the other when its first choice is missing. The repository, branch and project config come from there. The plugin also registers the `/ultrathink-<verb>` commands, the `ultrathink-sync` nudges, and the five ultrathink skills (`ultrathink-kickoff`, `ultrathink-sync`, `ultrathink-plan`, `ultrathink-ship`, `ultrathink-teach`). Hermes does not list plugin skills in the model's system prompt, so they load as `ultrathink:<name>` with `skill_view` (for example `ultrathink:ultrathink-kickoff`), and every instruction that names one also gives its absolute `SKILL.md` path.

`hosts/hermes/plugin.yaml` lists every hook: `pre_llm_call`, `transform_tool_result`, `post_tool_call`, `pre_verify`, `subagent_start`, `post_llm_call` and `on_session_finalize`. It also lists the tools `ultrathink_lesson_save` and `ultrathink_lesson_recall`. `register()` adds those two hooks, the two tools (hidden while `teach status` reports Teachable Moments off), the commands `/ultrathink-learn` and `/ultrathink-lessons`, and the skill `ultrathink-teach`. `post_llm_call` hands a finished turn to a detached `teach observe` when capture is `observe` or `auto`. `on_session_finalize` starts a detached `teach sync`. All of that fails open. Nothing in the plugin writes `~/.hermes/skills`. A Hermes skill is installed through Hermes `skill_manage`, so `skills.write_approval` applies. Teachable Moments state lives under the Hermes state directory's `teach/` (`${HERMES_HOME:-~/.hermes}/ultrathink/teach/`), never under `<cwd>/.planning`. See [Teachable Moments on Hermes](how-to/teachable-moments-on-hermes.md) (`docs/how-to/teachable-moments-on-hermes.md`).

### Install

```sh
mkdir -p ${HERMES_HOME:-~/.hermes}/plugins
ln -sfn <clone>/hosts/hermes ${HERMES_HOME:-~/.hermes}/plugins/ultrathink
hermes plugins enable ultrathink
hermes plugins doctor ultrathink
hermes config set plugins.hook_callback_timeout 600
```

Install the plugin as a symlink, not a copy. The plugin finds the engine by resolving the symlink, so the rest of `<clone>` must stay in place. A copied plugin directory has no engine beside it: it never starts Bun, and it logs one warning, `ultrathink: <path> not found; install hosts/hermes as a symlink into a full clone of ultrathink (docs/install.md#hermes-agent)`.

**The hook cap.** The last command is required, and nothing sets it for you: neither the plugin nor `scripts/setup.ts` changes your Hermes config. Hermes stops waiting for a plugin hook after `plugins.hook_callback_timeout` seconds: 30 by default, 600 at most. It is a global Hermes setting that applies to every plugin. A plan takes minutes, so it needs a cap of at least 105 s, and 600 is recommended. Under the default 30 s cap the planner never starts Bun: every prompt goes through unplanned, Hermes logs no hook timeout, and the Hermes log gets one `ultrathink: Hermes hook cap 30.0s leaves under 90s to plan, …` warning per process. Don't set it to 0: that turns off Hermes' hook deadline, and the turn waits on the hook.

The planner reads the cap Hermes enforces and stops the engine after `min(540, cap − 15)` seconds, which leaves 15 s for Hermes to take the plan. At a 600 s cap that is 540 s. `ULTRATHINK_HERMES_TIMEOUT` (seconds) replaces the 540. When the deadline is reached, the planner kills Bun's whole process group, including the engine calls Bun started, and the prompt goes through unplanned. Below a 105 s cap the deadline would be under 90 s, too short for a plan, so the planner doesn't start Bun at all. Every prompt then goes through unplanned, and the Hermes log gets one warning per process naming the fix, `hermes config set plugins.hook_callback_timeout 600`.

If your Hermes version does not report its hook cap to plugins, the planner reads `plugins.hook_callback_timeout` from the active profile's config: `${HERMES_HOME:-~/.hermes}/config.yaml` (or, when `active_profile` names a Hermes profile, `${HERMES_HOME:-~/.hermes}/profiles/<name>/config.yaml`). If that file sets none, it assumes Hermes' 30 s default and therefore never plans. Either way it logs one warning that names the value it used and the same fix. See [Troubleshooting](troubleshooting.md#hermes-the-plan-never-arrives).

ultrathink registers hooks, commands, skills and the two lesson tools. It does not replace built-in tools, so if `enable` asks about tool override, decline (or pass `--no-allow-tool-override`).

If another Hermes plugin already plans or rewrites prompts, disable it. Otherwise both will plan the same turn.

On Hermes the hook only plans. It never creates Notion or Linear rows. `ultrathink-kickoff` creates them at the start of the agent's turn by running `ultrathink-mcp track complete --state <file>`, so a plan that Hermes cuts off can't leave orphan rows. See [Tracking](tracking.md).

The plugin nudges the agent to run `ultrathink-sync` in two cases: when a tool call opens a pull request (`transform_tool_result`, `post_tool_call` and `pre_llm_call`), and, through Hermes' `pre_verify` hook, once per plan (per session and Graph ID) when a coding turn (one that edited files with `write_file` or `patch`) is about to finish with a tracked plan that has not been synced. A PR opened inside a `delegate_task` subagent counts too: the child's own `gh pr create` fires the same tool hooks (Hermes' `subagent_start` hook tells the plugin which parent it works for), so the parent gets the nudge on the delegate result that names the PR, or on its next turn. A delegate result that only cites a PR the child did not open is ignored. `pre_verify` sees only the parent agent's own `write_file`/`patch` edits, so a turn whose edits all ran in subagents gets no end-of-turn nudge. The nudge passes the state file (`stateFile=`), the Graph ID (`graphId=`) and, when the session opened one, the PR URL (`prUrl=`). Sync updates only the rows kickoff created, found by Graph ID (the nudge's `graphId=` wins when a newer prompt has since replaced the plan in the state file), and records `synced` in the session record, which stops the end-of-turn nudge. See [Tracking](tracking.md).

Hermes also gets a short handoff instead of the full specification: the spec path, the state file, the Graph ID and the kickoff instruction. The hook creates no rows on Hermes, so the handoff carries no Linked issues TODO lines: kickoff's `track complete` prints them once it has created the rows. Its human-in-the-loop step asks blocking questions with one Hermes `clarify` call (at most 5 questions of up to 4 choices, recommended default first) instead of `AskUserQuestion`, and names Hermes' `todo` and `delegate_task` tools for TodoWrite and Task subagents. The full XML and the graph stay in the spec file. Hermes appends hook context to the user message, replays it in every later turn, and spills any piece over 10,000 characters (`hooks.output_spill.max_chars`) to a file, keeping only its first and last 500 characters, so a full specification would be cut.

The plugin skips some prompts before Bun starts: cron runs, sessions with a parent session, empty prompts, prompts that start with `/`, and prompts that are already uplifted ultrathink XML. In shared multi-user gateway sessions Hermes prefixes each message with the sender's `[Name] ` tag; the plugin strips a leading tag only when it names the current sender (`HERMES_SESSION_USER_NAME`), before these checks, and sends the untagged text to the engine. A label you type yourself, such as `[backend] update the guide`, stays in the request. Hermes expands a skill command into its skill scaffold before `pre_llm_call` runs, so a prompt that still starts with `/` is never a skill with a task. The engine then skips a bare skill scaffold that carries no task, and, on every host, a prompt that references an existing ultrathink graph as `graph ut-<id>-<8 hex>` (as dispatched workers and the Linear issue footers do) unless you prefix it with `uplift:`. See [Commands](commands.md#prompt-prefixes-and-automatic-skips) for the other skips.

In gateways such as Telegram, `/ultrathink-quick` needs `plugins.entries.ultrathink.allow_gateway_injection: true` in the Hermes config. Without it, the command falls back to skipping the next message. See [Commands](commands.md).

### Verify

1. `hermes config get plugins.hook_callback_timeout` prints `600`.
2. `hermes plugins doctor ultrathink` prints `OK: runtime discovery, manifest parsing, import, and registration passed`, and `hermes plugins list` shows `ultrathink` as enabled. The plugin registers the hooks in `hosts/hermes/plugin.yaml`, including `post_llm_call` and `on_session_finalize`.
3. Start a Hermes session and run `/ultrathink-status`. Hermes replies inline with the state.
4. In a Hermes session, ask the agent to call its `skills_list` tool. The result includes `ultrathink:ultrathink-kickoff`, `ultrathink:ultrathink-teach` and the other ultrathink skills.
5. Send a non-trivial prompt. The short handoff reaches the model as context before its first call, the agent loads `ultrathink:ultrathink-kickoff`, and `${HERMES_HOME:-~/.hermes}/logs/agent.log` gets no new `Hook 'pre_llm_call' callback on_pre_llm_call timed out` line and no `ultrathink:` warning.

Verified live on Hermes Agent v0.21.4 through its real CLI command dispatcher: `/ultrathink-status`, `/ultrathink-track off`, and `/ultrathink-quick`, which injected the message with no plan.

### Update and uninstall

See [Upgrade and move](how-to/upgrade-and-move.md#upgrade) and [Uninstall](how-to/uninstall.md#hermes-agent). Uninstalling also covers putting the hook cap back if no other plugin needs it.

## Muse Code

Muse reads `.muse-plugin/plugin.json`. It declares the four skills, the six commands, and three hooks: `UserPromptSubmit` (`hooks/muse-prompt`, which runs the same prompt hook as Claude Code with a 600 s timeout), `PostToolUse` (`hooks/muse-post-tool`, the PR sync check) and `Stop` (`hooks/muse-stop`).

### Install

```sh
muse plugins validate <clone>
muse plugins install <clone> --scope user
muse plugins approve ultrathink
```

- `validate` prints `diagnostic=multiple-manifests severity=warning … selected .muse-plugin/plugin.json; ignoring .claude-plugin/plugin.json`. This warning is expected: the repository ships manifests for several hosts, and Muse picks its own.
- Muse refuses to install a plugin directory that contains symlinks. `bun install` can create symlinks under `node_modules/.bin`, so install from a clone where you have not run it, or delete `node_modules` first. ultrathink does not need `node_modules` at runtime.
- Muse puts third-party plugin hooks on hold until they are reviewed. Skills and commands are active as soon as the plugin is enabled, but planning starts only after `approve`.

### Verify

1. `muse plugins inspect ultrathink` shows `enabled=true active=true valid=true`, and each of the three hooks (`user-prompt-submit`, `post-tool-use`, `stop`) with `status=trusted_enabled`.
2. In Muse, run `/ultrathink-status`. The prompt hook blocks the command and shows the state.
3. Send a non-trivial prompt. The transcript shows the `Prompt Uplift ·` summary.

Verified live on Muse Code 1.4.0: `/ultrathink-status` and `/ultrathink-quick` in `muse exec`. A quick message was answered. In headless mode a blocked control command ends the run as `Cancelled`, so check status in the interactive UI.

### Update and uninstall

Muse runs a copy from its plugin cache, so `git pull` alone does not update it. See [Upgrade and move](how-to/upgrade-and-move.md#upgrade) and [Uninstall](how-to/uninstall.md#muse-code).

## Omp

Omp loads the extension listed under `omp.extensions` in `package.json` (`src/host/omp.ts`), plus the skills. With `think.engine: "auto"` the extension plans inside Omp on the session's own model, with Omp's own provider and login, so it needs no `claude`, `grok` or `muse` login (see [Choose the planning engine](how-to/choose-engine.md#omp-the-sessions-own-model)). It plans in `before_agent_start` and waits up to 25 s, because Omp caps a handler at 30 s. A plan that takes longer arrives as an aside message; on reasoning-heavy models that can take several minutes. In the TUI, the extension adds a live `ultrathink` status bar above Omp's status band and renders plans as cards.

### Install

```sh
omp plugin link <clone>
```

### Verify

1. `omp plugin list` shows `ultrathink@1.4.0` as enabled.
2. Start the Omp TUI. The `ultrathink` status bar appears above the status band.
3. Run `/ultrathink-status`. Omp shows the state as a notification. Before the first plan the `Engine:` line reads `omp-native:auto (live model not observed)`.
4. Send a non-trivial prompt. The status bar shows the planning stages and the planning model, for example `omp-native:<provider>/<model> [detected]`, and the plan appears as a card, either inline or later as an aside. Afterwards `/ultrathink-status` shows the same model on its `Engine:` line.

Verified live on Omp 18.3.1 in the interactive UI: `/ultrathink-status` showed the notification, and `/ultrathink-quick` was answered with no plan. Use the interactive UI for these commands. In `omp -p` print mode, notifications are not shown and a quick message is not processed before Omp exits.

Native planning was verified live on Omp 18.8.0 in print mode, with the session model `openai-codex/gpt-6.1-sol`: the record read `omp-native:openai-codex/gpt-6.1-sol [detected]`, the agent got the pending note after 25 s, and the plan (7 graph nodes, 3 clarifying questions) arrived as an aside about 336 s after the prompt. A print-mode run that exits before the plan arrives cancels it, so the agent must keep working, or the session stay open, until the aside lands.

If something looks wrong, `omp plugin doctor` checks the installed plugins.

### Update and uninstall

See [Upgrade and move](how-to/upgrade-and-move.md#upgrade) and [Uninstall](how-to/uninstall.md#omp).

## Prime Agent

Prime Agent runs the agent in a persistent Python kernel and has no prompt hook, so ultrathink is a Python-backed skill there: `hosts/prime-agent` (a `SKILL.md`, a `pyproject.toml` and the package `src/ultrathink`). The kernel loads it as `ultrathink`, and the agent plans by calling `await ultrathink("<request>")`. The call runs `hooks/engine.ts` through `bin/run-bun` with the host `prime-agent`, the Prime Agent session id and the kernel's working directory, and returns the engine's response to the kernel: `planned`, `context` (the plan text, the same text the other hosts inject), `spec` and `spec_path`, `state_path`, `graph_id`, `summary`, `view` and `model_resolution`. Nothing is planned until the agent calls it; the skill description tells the agent to plan non-trivial requests, `/ultrathink-*` commands and `/skill:gsd-*` runs. The `ultrathink-kickoff`, `ultrathink-plan`, `ultrathink-sync`, `ultrathink-ship` and `ultrathink-teach` skills are linked into `~/.agents/skills`, the shared Agent Skills directory Prime Agent reads, so `/skill:ultrathink-kickoff` works as on the other hosts. State lives in `${PRIME_AGENT_CODING_AGENT_DIR:-~/.prime/agent}/ultrathink/`. Planning runs on the Claude CLI route by default; `think.engine` and `models.hosts.prime-agent` choose another.

### Install

```sh
bun <clone>/scripts/setup.ts apply
```

`apply` links `<clone>/hosts/prime-agent` to `${PRIME_AGENT_CODING_AGENT_DIR:-~/.prime/agent}/skills/ultrathink` and each `<clone>/skills/<name>` to `~/.agents/skills/<name>` (`ULTRATHINK_AGENT_SKILLS_DIR` overrides the directory). An existing symlink is retargeted; a real directory at either path is kept and reported, so link it yourself or move it first. Then start a new Prime Agent session (or run `/reload`): the kernel installs the package editable into its venv (`~/.prime/agent/kernel-venv`) and exposes `ultrathink`. Python 3.10 or later; no third-party packages.

### Verify

1. In a Prime Agent session, `await ultrathink.status()` shows `host: prime-agent`, `engine_present: True`, the state directory and the `ultrathink status` text (planning on, the engine route, tracking).
2. `await ultrathink("ok")` returns `planned: False` with `skipped: precheck-skip` (a trivial prompt is never planned).
3. `await ultrathink("add a /health endpoint returning uptime and git sha")` returns `planned: True` after one to five minutes, with `context`, `spec_path` under the state directory and, when tracking is configured, the row links. `ultrathink.last()` returns the carrier (`last-plan.json`) afterwards.
4. `/skill:ultrathink-kickoff` loads the kickoff skill.

Tracking from Prime Agent uses the shared MCP gateway through the kickoff and sync skills: log in with `bin/ultrathink-mcp auth login linear` and `notion` from the clone. Teachable Moments: `ultrathink.teach("status")`, `ultrathink.teach("recall", "<query>")`; promoted skills install into `~/.prime/agent/skills/<name>/SKILL.md` with `--target prime-agent --install`.

### Update and uninstall

The skill is a symlink into the clone, so `git pull` updates it; start a new session afterwards. `bun <clone>/scripts/setup.ts rollback` removes the symlinks it created (only links that point into the clone), and leaves the state directory. A Python environment the kernel created inside `hosts/prime-agent` (`.venv`, `uv.lock`) is ignored by git.

## Cursor

Cursor loads skills from `.cursor-plugin/plugin.json` (`skills`) and commands from the `commands` paths in that file (`./hosts/cursor/commands` and `./hosts/cursor/gsd-commands`). Planning is a `beforeSubmitPrompt` hook, separate from the pstack bridge. The hook runs `hooks/engine.ts` with host `cursor` and puts the plan in `additional_context`. It fails open: a missing Bun, a planner error, a child or swarm session, or a wait past `ULTRATHINK_CURSOR_BUDGET_MS` (default 180000) leaves the prompt unchanged. A child that ignores SIGTERM is killed one second after the budget. Plans use the Claude CLI, the same default as Hermes and Prime Agent. State is `~/.cursor/ultrathink`. Run status with `ULTRATHINK_HOST=cursor`; host detection does not treat `CURSOR_AGENT` as this host, because that variable is set for other work on the same machine.

The hook does not start Agent Swarm. When `.cursor/agents/a01-orchestrator.md` is installed, the `ultrathink-cursor` skill tells the agent to spawn `a01-orchestrator` once with the Graph ID. Questions, short replies, and `/ultrathink-quick` stay in the current session.

Control commands (`/ultrathink-on`, `/ultrathink-off`, `/ultrathink-skip`, `/ultrathink-track on|off`, `/ultrathink-status`) are answered by the hook. It runs `bin/ultrathink` with host `cursor` and blocks the prompt with that output, so no model turn runs. If the hook cannot answer, the command files in `hosts/cursor/commands` run the same checkout, found through `~/.cursor/hooks/ultrathink-cursor-plan.root`.

The installer does not install the plugin's skills. Cursor loads `ultrathink-cursor` and `ultrathink-kickoff` only when it loads this clone as a plugin through `.cursor-plugin/plugin.json`. The plan the hook injects names those skills, so outside this clone, make sure Cursor loads the plugin before you rely on the swarm handoff.

A prompt that is `/gsd-*` or `/skill:gsd-*` is planned even when no GSD skill file is installed. The planner uses the text after the command name. `/ultrathink-quick` and the other `/ultrathink-*` commands are still not planned, and neither is an unknown command such as `/model`. The pstack hook (`ultrathink-managed`) still adds its skill paths on a `/gsd-*` invocation when `pstack.enabled` is true. The two hooks use different markers and do not replace each other.

On Cursor only, the planner also finds a skill or command you type from Cursor's own folders: `~/.cursor/skills/<name>/SKILL.md`, `~/.cursor/commands/<name>.md`, the same two under the workspace's `.cursor/`, and the skills of the newest completed pstack plugin under `~/.cursor/plugins/cache/cursor-public/pstack/`. Other hosts do not search those folders, so a Cursor-only skill still skips planning there. The pstack cache path matches `src/cursor/pstack.ts`. The personal and workspace folder names are not checked against Cursor's documentation or a live Cursor session.

### Connect

1. Clone this repo, [agent-substrate](https://github.com/swcstudiospace/agent-substrate), and [agent-swarm](https://github.com/swcstudiospace/agent-swarm). Bun 1.2 or newer must be installed (`bin/run-bun` also looks in `~/.bun/bin/bun`).
2. From a shell, with the three checkout paths:

```sh
SUBSTRATE_ROOT=<substrate-clone> SWARM_ROOT=<agent-swarm-clone> \
  bun <ultrathink-clone>/scripts/cursor-plugin.ts install --target <workspace>
```

`SUBSTRATE_ROOT` and `SWARM_ROOT` are optional. Leave one unset and that checkout is skipped. `--target` is the workspace that receives Agent Swarm's Cursor agents. Without it, the swarm installer does not run.

3. Set these in the environment Cursor uses. The installer never writes their values:
   - `SUBSTRATE_URL` — substrate HTTP origin. The MCP entry is the literal `${SUBSTRATE_URL}/mcp`.
   - `SUBSTRATE_TOKEN` — bearer token. The MCP entry is the literal `Bearer ${SUBSTRATE_TOKEN}`.
   - `SWARM_ROOT` — absolute agent-swarm checkout, the same path you passed to `install` when you want the agents copied.
   - `ULTRATHINK_HOST` — set to `cursor` when you run `bin/ultrathink` from a shell that is not Cursor.

4. What `install` writes:
   - `~/.cursor/hooks.json`: one `beforeSubmitPrompt` command with `ultrathink-cursor-managed: true`, plus the staged script `~/.cursor/hooks/ultrathink-cursor-plan.js` and `ultrathink-cursor-plan.root`. An existing `ultrathink-managed` (pstack) or `substrate-managed` entry stays.
   - `~/.cursor/hooks.json` substrate entries, when `SUBSTRATE_ROOT` is set and the projector is present: `sessionStart`, `postToolUse`, and `stop`, each `substrate-managed`.
   - `~/.cursor/mcp.json`: an HTTP `substrate` server whose URL and Authorization header are the placeholders above. A different existing `substrate` entry is left untouched.
   - `<workspace>/.cursor/agents/<slug>.md` and `<workspace>/.cursor/rules/agent-swarm.mdc`, when `SWARM_ROOT` and `--target` are set.
   - `~/.cursor/commands/<name>.md` for each GSD command the pstack stage table already knows (`gsd-discuss-phase`, `gsd-plan-phase`, `gsd-execute-phase`, `gsd-quick`, `gsd-ship`, `gsd-autonomous`, and the rest of that table). Each file contains the marker `ultrathink-cursor-gsd`. A file that is already there without the marker, including one installed by a GSD plugin, is not replaced.

5. Start a new Cursor session so the hooks load. Type `/gsd-plan-phase` (or another `/gsd-*` name) plus the phase or task. The planner runs before the agent continues the GSD workflow.

`install` again refreshes the planner entry and the marked command files, and leaves `ultrathink-managed` and `substrate-managed` entries in place. `remove` deletes the planner entry, the staged hook, and command files that carry the marker:

```sh
bun <ultrathink-clone>/scripts/cursor-plugin.ts remove
```

The installer never writes a token and never runs `swarm_run.py` or `hooks/autonomous_run.py`.

### Verify

1. `~/.cursor/hooks.json` has one `beforeSubmitPrompt` command whose entry is `ultrathink-cursor-managed`, and the pstack entry is still there if you installed it.
2. `ULTRATHINK_HOST=cursor <ultrathink-clone>/bin/ultrathink status` prints the Cursor state directory (`~/.cursor/ultrathink`).
3. `~/.cursor/commands/gsd-plan-phase.md` exists and contains `ultrathink-cursor-gsd`. `~/.cursor/mcp.json` names `SUBSTRATE_URL` and `SUBSTRATE_TOKEN` and does not contain a token value.
4. Send a non-trivial prompt. The agent receives the plan, including a Cursor swarm note and the Graph ID when one was minted. A prompt that is a question, or `/ultrathink-quick`, is not handed to `a01-orchestrator`. A `/gsd-*` prompt is planned. `/ultrathink-quick` is not.

This adapter is source-present. It has not been verified in a live Cursor session.

## `scripts/setup.ts` reference

`bun <clone>/scripts/setup.ts <apply|status|rollback>` works on the clone that contains the script, whatever directory you run it from. With no argument it runs `status`. Grok Build and Prime Agent need `apply`. The other hosts do not, but `apply` also sets up Claude Code when the `claude` CLI is installed.

| Subcommand | What it does |
|---|---|
| `apply` | 1. Writes the Grok hook file `${GROK_HOME:-~/.grok}/hooks/ultrathink.json` and installs the Grok rule `${GROK_HOME:-~/.grok}/rules/ultrathink.md`. The rule is written from `hosts/grok/ultrathink.md` when missing; otherwise only its ultrathink marker block is replaced, or appended when absent, and the rest of the file is kept.<br>2. If the `claude` CLI is installed, adds the hosted Notion (`https://mcp.notion.com/mcp`) and Linear (`https://mcp.linear.app/mcp`) HTTP MCP servers to Claude Code at user scope, unless a server named exactly `notion` or `linear` is already configured. It checks with `claude mcp get <name>`, then falls back to an exact name match in `claude mcp list`, so a server with a similar name or URL does not count.<br>3. Runs `claude plugin marketplace add <clone>` and `claude plugin install ultrathink@ultrathink`.<br>4. Merges a tracking block into `${CLAUDE_CONFIG_DIR:-~/.claude}/CLAUDE.md` between `<!-- ultrathink:start -->` and `<!-- ultrathink:end -->`, updating it in place on re-runs. The block says the plugin *can* track work, and that its tracking workflow applies only when `/ultrathink-status` shows a Notion database or a Linear team. Without either, ultrathink creates no rows.<br>5. Records which MCP servers it added in `${CLAUDE_CONFIG_DIR:-~/.claude}/ultrathink-setup-state.json`. A re-run keeps earlier records, so a server added by any `apply` stays recorded.<br>6. Links the Prime Agent host: `<clone>/hosts/prime-agent` to `${PRIME_AGENT_CODING_AGENT_DIR:-~/.prime/agent}/skills/ultrathink` and `<clone>/skills/<name>` to `${ULTRATHINK_AGENT_SKILLS_DIR:-~/.agents/skills}/<name>`; an existing symlink is retargeted, anything else is kept and reported.<br>7. Prints the install commands for Hermes (one `mkdir -p … && ln -sfn … && hermes plugins enable ultrathink` line honoring `HERMES_HOME`, then the hook cap step), Muse and Omp, with the clone path quoted so you can paste them.<br>Without the `claude` CLI, steps 2 to 5 are skipped with the notice `Claude Code: claude CLI not found — skipped …`. |
| `status` | Reports whether the Grok rule (with its marker block), the Grok hook file and the Prime Agent skill link are installed. With the `claude` CLI, it also reports whether Claude Code has servers named exactly `notion` and `linear`, and whether the `CLAUDE.md` block is present. Without it, it prints `Claude Code: claude CLI not found` followed by the Grok lines. |
| `rollback` | Removes the Grok hook file and the Grok rule (the whole file if it holds only the ultrathink block, otherwise just the block). Removes the Prime Agent symlinks that point into the clone. Removes the `CLAUDE.md` block. Removes the `notion` and `linear` Claude Code MCP servers only if an `apply` run recorded adding them and `claude mcp get` still shows them as user-scope HTTP servers with the hosted URL; a changed entry is left in place, a missing one is reported as `already removed`. Then it deletes the setup state file. If a removal fails, it says so and keeps the state file, so running `rollback` again retries it. It does not uninstall the Claude Code plugin: its last line prints `claude plugin uninstall ultrathink@ultrathink && claude plugin marketplace remove ultrathink` for you to run. |

`apply` is idempotent. The hosted servers from step 2 connect Claude Code directly to Notion and Linear. If you would rather use the [shared MCP gateway](#shared-mcp-gateway) in Claude Code too, note that `scripts/mcp-register.ts` keeps a same-named entry that is not ultrathink's, and reports it as `kept`. Run `bun scripts/mcp-register.ts --replace --hosts claude` to swap the hosted `notion` and `linear` entries for gateway entries; later `apply` runs leave them alone. `rollback` removes the `notion` and `linear` entries only while they are still the user-scope HTTP servers `apply` added, with the hosted URL. An entry you replaced since, such as a gateway entry from `mcp-register --replace`, is left in place and reported as `left in place: <name> was changed since setup added it`; remove gateway entries with `bun scripts/mcp-register.ts --remove`.

For a full removal, see [Uninstall](how-to/uninstall.md).

## Shared MCP gateway

`bin/ultrathink-mcp` is a stdio MCP server that relays to the hosted Notion, Linear and Greptile MCP servers. It adds credentials from one store, `${XDG_CONFIG_HOME:-~/.config}/ultrathink/mcp-credentials.json` (mode 0600; `ULTRATHINK_MCP_STORE` overrides the path). The planner creates tracking rows through the same store, and the ship loop uses it for Greptile. Register the gateway in each host and log in once. [Register the MCP gateway](how-to/register-mcp-gateway.md) has the full walkthrough.

### Register it in every host

```sh
bun <clone>/scripts/mcp-register.ts --dry-run   # show what would change
bun <clone>/scripts/mcp-register.ts
```

This registers three servers, `notion`, `linear` and `greptile`, each running `<clone>/bin/ultrathink-mcp serve <provider>`, in each host's user-level config:

- An entry whose command ends in `/bin/ultrathink-mcp` is ultrathink's. If it points at another clone, it is replaced; if it already matches, it is reported as `unchanged`.
- Only the user-scope entry counts. A same-named entry in a local or project scope is left alone.
- A same-named entry that runs something else is kept and reported as `kept: existing entry is not ultrathink's; rerun with --replace to overwrite it`. `--replace` overwrites it.
- `--remove` deletes only ultrathink's entries. See [Uninstall](how-to/uninstall.md#3-remove-the-mcp-gateway-entries).
- Every file it changes is backed up as `<file>.bak-ultrathink-mcp-<timestamp>`.
- Claude Code, Grok and Hermes are skipped when their CLI is not on `PATH`. Limit the run with `--hosts claude,grok,hermes,muse,omp` and `--providers notion,linear,greptile`. It exits non-zero if any registration failed.
- Run it from a clone in a stable directory. From a path containing `/plugins/cache/` it prints a warning, because the next plugin update would replace that copy and break the registered commands.

| Host | How it registers | File backed up |
|---|---|---|
| Claude Code | `claude mcp remove` / `claude mcp add --scope user` | `${CLAUDE_CONFIG_DIR:-~}/.claude.json` |
| Grok Build | `grok mcp add --scope user` | `${GROK_HOME:-~/.grok}/config.toml` |
| Hermes Agent | `hermes mcp remove` / `hermes mcp add`. Hermes saves a server it cannot connect to yet as disabled, which the script reports as `saved disabled`. Run the script again after logging in. | `${HERMES_HOME:-~/.hermes}/config.yaml`, or the active profile's `${HERMES_HOME:-~/.hermes}/profiles/<name>/config.yaml` |
| Muse Code | Edits the file directly (`mcpServers`, `mode: "optional"`) | `${XDG_CONFIG_HOME:-~/.config}/muse/settings.json` |
| Omp | Edits the file directly | `${PI_CODING_AGENT_DIR:-~/.omp/agent}/mcp.json` |

### Log in

```sh
<clone>/bin/ultrathink-mcp auth set-key linear --stdin      # paste a Linear API key
<clone>/bin/ultrathink-mcp auth set-key greptile --stdin    # paste a Greptile API key
<clone>/bin/ultrathink-mcp auth login notion                # Notion supports OAuth only
<clone>/bin/ultrathink-mcp auth status
```

Linear and Greptile also accept an OAuth login (`auth login linear`, `auth login greptile`) instead of an API key. `set-key` also accepts `--env-file <path> --var <NAME>` to read the key from a dotenv file. An OpenRouter key is checked before it is stored: its format must be `sk-or-…`, and one non-destructive request to OpenRouter's key endpoint must accept it. A rejected key is not stored. Pass `--no-verify` to store it after the format check only (for an offline machine). `auth login` starts a browser OAuth flow with a callback on `127.0.0.1:8765` on the machine running the command. For a login over SSH or on a machine without a browser, see [Set up Notion](how-to/set-up-notion.md) and [Troubleshooting](troubleshooting.md#notion-oauth-over-ssh). `auth logout <provider>` removes a provider's stored credentials.

### Check it

```sh
<clone>/bin/ultrathink-mcp check            # all three providers
<clone>/bin/ultrathink-mcp check linear     # one provider
```

For each provider, `check` sends `initialize` and `tools/list` through the gateway and prints `<provider>: OK <n> tools` or `<provider>: FAIL <reason>`. It exits non-zero if any provider fails.

Credentials alone create no rows. The planner creates rows only for providers configured in your config: Linear needs `linear.team` and Notion needs `notion.dataSourceUrl`. See [Tracking](tracking.md).

## Engine selection

The engine is the model that writes the spec, the Graph of Thought and the clarifying questions. It is chosen per host state directory, in this order:

1. The engine set with `bin/ultrathink grok engine auto|claude|grok|muse` for that host, stored in its state directory. `auto` follows the config.
2. `think.engine` in config: a named engine, or `"auto"` (the default), which resolves to the host's own engine below.
3. The host's own engine: Claude on Claude Code, Grok on Grok Build, Muse on Muse Code, the route of the session model's family on Hermes (Claude for an unknown family), and on Omp the session's own live model, planned natively. A named engine on Omp opts out of native planning.

Claude replaces a selected Grok route only through the two explicit, labeled user switches: `grok.fallbackToClaude: true` (HTTP/CLI login missing or expired) and `grok.enabled: false` (documented ‘forces Claude even when Grok is selected’). Without them, a missing or expired Grok login skips planning with the unchanged `GROK_LOGIN_REQUIRED` notice. Naming `think.engine: "claude"` is a deliberate engine choice, not a replacement.

```sh
<clone>/bin/ultrathink grok                       # engine label, Grok model/effort/transport, Grok login status
<clone>/bin/ultrathink grok engine grok           # switch Claude Code's engine to Grok
ULTRATHINK_HOST=omp <clone>/bin/ultrathink grok engine auto    # Omp follows the config again
```

To switch every host, set it in config, for example in `${XDG_CONFIG_HOME:-~/.config}/ultrathink/config.json`:

```json
{ "think": { "engine": "grok" } }
```

- **Claude** runs the `claude` CLI headless (`claude -p`) on your own Claude plan login (sign in with `claude`, then `/login`; on a machine without a browser run `claude setup-token` and export `CLAUDE_CODE_OAUTH_TOKEN`). With the default `claude.auth: "plan"`, `ANTHROPIC_API_KEY` is kept away from the child process, because Claude Code always prefers that key to your plan login in `-p` mode. The default model `claude-haiku-5-5` needs Claude Code 2.1.293 or newer. Its status label is `claude:<model>`, for example `claude:claude-haiku-5-5`. `bin/ultrathink doctor` checks the version and the login.
- **Grok** has three transports. `http` (default) and `cli` use your `grok login` session; if it is missing or expired, the prompt goes through unplanned with ``Prompt Uplift skipped · Grok login required (run `grok login`)``, under `auto` on Grok Build too, unless one of the two switches above is set. The default model is `grok-build-0.1`; where the session cannot use it, the route continues with `grok.fallbackModels` (`grok-4.7` by default). `shunt` posts to an Anthropic-compatible gateway that you run and name in `grok.shuntBaseUrl`. There is no built-in gateway: with `shunt` selected and `grok.shuntBaseUrl` empty, the prompt goes through unplanned with ``Prompt Uplift skipped · grok:unresolved [transport-incompatible]`` and nothing is sent.
- **Omp's native planning** uses the session's own model and Omp's login, and shows labels such as `omp-native:<provider>/<model> [detected]`. See [Choose the planning engine](how-to/choose-engine.md#omp-the-sessions-own-model).
- **Muse** runs the `muse` CLI headless (`muse exec --json`) for one agent turn per call, with the shell, file writes and web tools disabled. Its label is `muse:<model>`, for example `muse:muse-spark-1.3-contributor`.

[Choose an engine](how-to/choose-engine.md) compares them, and [Configuration](configuration.md#key-reference) lists every `claude.*`, `grok.*` and `muse.*` key with its default.

Whichever engine you choose, a failed or timed-out planning call never blocks your prompt. The turn continues with a minimal fallback spec, creates no tracking rows, and the summary line reports `Engine error · …`. See [Troubleshooting](troubleshooting.md).

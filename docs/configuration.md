# Configuration

ultrathink reads JSON config files, a small per-host control file written by the `/ultrathink-*` commands and `bin/ultrathink`, and some environment variables. All of them are optional. With no config at all, ultrathink plans every non-trivial prompt with each host's own engine (see [Host defaults](#host-defaults)) and contacts nothing except the engine: it creates no Linear or Notion rows, requests no Agent Substrate brief, reads no Greptile knowledge base, asks no Jev decision, stores no lessons, contacts no Hindsight or RAGFlow server, and never pushes, opens a pull request or merges.

Terms used on this page:

- **Host**: the coding agent ultrathink runs inside: Claude Code, Grok Build, Hermes Agent, Muse Code, Omp, Prime Agent or Cursor.
- **Engine**: the model that writes the plan. On Omp with `think.engine: "auto"` it is the session's own live model, called inside Omp. Everywhere else, and on Omp with a named engine, it is Claude, Grok or Muse on its CLI route (Grok also over HTTP or a gateway you run).
- **Graph of Thought**: the 5 to 8 reasoning nodes the engine builds for each prompt. Each node is filled with numbered rationale steps.
- **HITL** (human in the loop): the clarifying questions the plan asks before work starts.
- **Tracker**: Notion and/or Linear, where the plan becomes rows and issues.
- **Ship**: the optional flow that opens a pull request, has Greptile review it and can merge it. See [Ship](ship.md).
- **State directory**: the per-host directory where ultrathink keeps its control file and session records. See [State directories](#state-directories).
- **Hindsight**: an optional memory server that stores confirmed lessons. Off until you opt in.
- **RAGFlow**: an optional document search that can add excerpts to a plan. Off until you opt in.
- **Teachable Moments**: optional lessons captured from a session and recalled into a later plan. Off until you opt in. State lives under the host state directory's `teach/`, never under `<cwd>/.planning`.

Contents:

- [Config files](#config-files)
- [Key reference](#key-reference)
- [Full example](#full-example)
- [Environment variables](#environment-variables)
- [State directories](#state-directories)
- [Control state versus config](#control-state-versus-config)

## Config files

Every host reads the same three files. They are merged in this order, and a later file wins:

| Order | File | Notes |
|---|---|---|
| 1 | `~/.config/ultrathink/config.json` | Host-neutral user config. Uses `$XDG_CONFIG_HOME/ultrathink/config.json` when `XDG_CONFIG_HOME` is set. `bin/ultrathink-mcp notion init --write-config` writes here. |
| 2 | `~/.claude/ultrathink.json` | Claude user config. Uses `$CLAUDE_CONFIG_DIR/ultrathink.json` when `CLAUDE_CONFIG_DIR` is set. Read on every host, not only Claude Code. |
| 3 | `<project>/.claude/ultrathink.json` | Project config, read from the working directory of the session. |

How the merge works (`src/config.ts`):

- Merging is per key inside each section. A project file that sets only `{"hitl": {"maxQuestions": 2}}` changes that one key and keeps everything else.
- A missing file, a file that is not valid JSON, or a file whose top level is not an object is skipped.
- Unknown sections and keys are ignored.
- A value with the wrong type or outside its allowed range is ignored, and the value from the earlier file (or the default) stays.
- Some string keys only accept a non-empty value, so an empty string in a later file does not clear a value an earlier file set: `notion.dataSourceUrl`, `linear.team`, `grok.baseUrl`, `grok.model`, `grok.bin`, `grok.shuntModel`, `claude.bin`, `decisions.model`, `hindsight.url`, `hindsight.bank`, `ragflow.url`, and the URL keys `grok.shuntBaseUrl` and `substrate.url`. To stop row creation, use `/ultrathink-track off` (see [Turning tracking off](tracking.md#turning-tracking-off)). To turn the Agent Substrate brief off, set `SUBSTRATE_DISABLED=1`.
- The URL keys `grok.shuntBaseUrl` and `substrate.url` must be `http://` or `https://` URLs. Trailing slashes are removed.
- The project file cannot set `claude.bin`, `claude.settingSources`, `grok.bin`, `grok.home`, `grok.baseUrl`, `grok.shuntBaseUrl` or `muse.bin`. Together they choose which program runs, where your Grok login is read from, and which URLs receive your prompts and Grok token. A cloned repository must not choose these, so only the two user files set them and a project value is ignored. `grok.baseUrl` and `grok.shuntBaseUrl` must be `http://` or `https://` URLs.
- Millisecond budgets are capped at 2147483647 ms, the timer maximum. A larger value is set to the cap, not rejected, and `0` still means no timer. The capped keys are `claude.callTimeoutMs`, `claude.budgetMs`, `grok.callTimeoutMs`, `muse.callTimeoutMs` and `track.budgetMs`.
- `pstack` is user-only. The merge ignores a project file's whole `pstack` section, so `pstack.enabled: true` there does not turn the Cursor bridge on. The Cursor hook never reads the project file. See [`pstack`](#pstack-cursor-bridge).
- The project file can only make Jev decisions more restrictive: there, `decisions.zdr` can only turn zero data retention on (a `false` is ignored), and `decisions.points` can only drop points (it is intersected with the list from the earlier files, or the default). `decisions.enabled` is ignored in every file: Jev is always on, and only `ULTRATHINK_DECISIONS=0` turns it off. The other `decisions` keys (`provider`, `model`, `timeoutMs` and the thresholds) merge as usual, and the two user files merge every key as usual. See [`decisions`](#decisions-jev-decisions-openrouter-decisions-api).
- The project file can only tighten Hindsight, RAGFlow and Teachable Moments. For `hindsight`, only `enabled: false` counts; `url`, `bank` and the timeouts are ignored, so a repository cannot point memory traffic at its own host. For `ragflow`, only `enabled: false` and `ground: false` count; `url`, `datasetIds` and the other keys are ignored. For `teach`, `enabled`, `recall` and `autoPromote` can only turn off, and `capture` can only go down (`auto` to `observe` to `explicit`); the other `teach` keys are ignored. The two user files merge every key as usual. See [`hindsight`](#hindsight-memory-server), [`ragflow`](#ragflow-document-search) and [`teach`](#teach-teachable-moments).
- The project file cannot set `state.retentionDays`: the whole `state` section is ignored there, because a repository must not be able to delete your session history. See [`state`](#state-session-retention).

`bin/ultrathink status`, run from the project directory, prints the merged result for the parts most people change. See [Commands](commands.md#binultrathink) for its output.

## Key reference

Types: "integer" means a whole JSON number; "number" allows fractions. Ranges are inclusive.

### `uplift`: prompt uplift

| Key | Type | Default | Meaning |
|---|---|---|---|
| `enabled` | boolean | `true` | Plan prompts. When `false`, only prompts that start with `uplift:` are planned. `/ultrathink-off` and `/ultrathink-on` override this per host. |
| `skipTrivial` | boolean | `true` | Skip trivial acknowledgements such as `ok` or `lgtm`. |
| `maxChars` | number, >= 0 | `0` | `0` means no limit: every prompt is sent to the engine. A positive value caps the uplift call: a longer prompt is not sent, gets the conservative fallback spec, and creates no rows. |
| `echo` | boolean | `true` | Accepted but not read. The one-line summary after each plan is controlled by `claude.echo`. |

### `think`: Graph of Thought

| Key | Type | Default | Meaning |
|---|---|---|---|
| `enabled` | boolean | `true` | Build the Graph of Thought. `bin/ultrathink think on\|off` overrides this per host. |
| `minNodes` | integer, >= 1 | `5` | Fewest graph nodes. Clamped to `maxNodes`. |
| `maxNodes` | integer, >= `minNodes` | `8` | Most graph nodes. Values above 8 are capped at 8. |
| `engine` | `"auto"`, `"claude"`, `"grok"` or `"muse"` | `"auto"` | Engine for the uplift, the graph, the per-node fills, the HITL questions and the ship judge. `"auto"` uses each host's own engine (see the matrix below). A named engine plans on every host. `bin/ultrathink grok engine auto\|claude\|grok\|muse` overrides this per host. |

Each node gets 4 to 8 numbered rationale steps. That range is fixed in code, not configurable. Each step becomes one sub-issue when tracking is on.

### `hitl`: clarifying questions

| Key | Type | Default | Meaning |
|---|---|---|---|
| `enabled` | boolean | `true` | Generate clarifying questions. `bin/ultrathink hitl on\|off` overrides this per host. |
| `maxQuestions` | integer, 1 to 4 | `4` | Most questions per prompt. |
| `knowledgeBase` | boolean | `false` | Opt-in. Before the clarifying questions, read the repository's Greptile knowledge base and let the clarifier settle questions it answers instead of asking them. Needs HITL on and a stored Greptile credential (`bin/ultrathink-mcp auth login greptile`, or `bin/ultrathink-mcp auth set-key greptile --stdin`). When `ship.greptileOrganization` is set, it is sent as the organization; an account in several organizations needs it. |

How the knowledge-base read works when `knowledgeBase` is `true` (see [Use the Greptile knowledge base](how-to/use-greptile-knowledge-base.md) for a walk-through):

- While the prompt is uplifted, ultrathink finds the repository's knowledge base on Greptile by the git remote's `owner/repo`, lists its documents and reads `index.md`.
- After the Graph of Thought, it picks up to 3 documents from the routing table in `index.md` that match the request and reads them. At most 24,000 characters go to the clarifier, marked as untrusted evidence, not instructions.
- Each stage has a 20-second budget. Any failure (no credential, no knowledge base for the repository, a Greptile error, a timeout) fails open: you get exactly the questions you would get with the key off.
- Only list and read calls go to Greptile's hosted MCP (`https://api.greptile.com/mcp`): the organization, the knowledge-base namespace id and document paths. Nothing from your prompt or your code is sent to Greptile. The documents read go to the planning engine inside the clarify call.
- Questions the knowledge base settled are not asked. They appear in their own `### Settled from the Greptile knowledge base` subsection of the Clarifications (HITL) block as `(Greptile knowledge base: <document>)`, marked as untrusted evidence the agent checks against the repository (asking you when the repository disagrees), not as your decisions, and in the spec's `CLARIFICATIONS` block as `<ANSWER source="knowledge" evidence="…">`. They are not carried to the next prompt. A claim that cites a document that was not read, or is otherwise invalid, is asked as an ordinary question. Product decisions are still asked.
- Each lookup is shown in the summary (`Knowledge · 3 docs · 1 settled`, `Knowledge · none`, `Knowledge · off (no Greptile login)` or `Knowledge · error`), in the session record's `knowledge` field, in a `## Greptile knowledge base` section of the plan context when documents were used, in the `ULTRATHINK_DEBUG=1` log as `greptile knowledge base: …`, and as a `kb` segment in the Omp status bar. `bin/ultrathink status` shows the `Knowledge base:` line. See [Troubleshooting](troubleshooting.md#greptile-knowledge-base) when it does not read what you expect.

### `claude`: the Claude engine

The Claude engine runs the `claude` CLI headless. It uses your existing Claude Code login.

| Key | Type | Default | Meaning |
|---|---|---|---|
| `bin` | string | `"claude"` | The `claude` binary. |
| `model` | string | `"sonnet"` | Model alias or name for the planning calls. `""` uses the CLI's default model. |
| `thinking` | boolean | `false` | Allow extended thinking in the planning calls. Slower. When `false`, the child calls run with `MAX_THINKING_TOKENS=0`. |
| `settingSources` | string | `""` | Passed as `--setting-sources` to the planning calls. `""` loads none, which is fastest and keeps other hooks out of the child calls. |
| `callTimeoutMs` | number, >= 0 | `0` | Timeout for one planning call. `0` means no timer. |
| `budgetMs` | number, >= 0 | `0` | Budget for the whole planning pass. `0` means run until the host's hook timeout. |
| `concurrency` | number, > 0 | `3` | Node fills that run in parallel within one dependency level. Rounded down, at least 1. |
| `echo` | boolean | `true` | Show a one-line summary to the user after each plan. |

### `grok`: the Grok engine

Used when the engine resolves to Grok: on Grok Build by default, or anywhere with `think.engine` set to `"grok"` (or `bin/ultrathink grok engine grok` on that host). See [Choose an engine](how-to/choose-engine.md).

| Key | Type | Default | Meaning |
|---|---|---|---|
| `enabled` | boolean | `true` | When `false`, the Claude engine is used even if `think.engine` is `"grok"`. The plan's model line then reads `claude:<model> [configured fallback · grok unavailable]`. |
| `transport` | `"http"`, `"cli"` or `"shunt"` | `"http"` | `http`: POST `{baseUrl}/responses` with your `grok login` token. `cli`: run the `grok` binary. `shunt`: POST `{shuntBaseUrl}/v1/messages` on an Anthropic-compatible gateway that you run, with no auth. |
| `baseUrl` | string | `"https://cli-chat-proxy.grok.com/v1"` | Base URL for the `http` transport. Trailing slashes are removed. |
| `model` | string | `"grok-4.7"` | Model for `http` and `cli`, and for `shunt` when `shuntModel` is empty. |
| `reasoningEffort` | `"low"`, `"medium"`, `"high"` or `"xhigh"` | `"xhigh"` | Reasoning effort for `http` and `cli`. |
| `bin` | string | `"grok"` | The `grok` binary. |
| `home` | string | `""` | Grok home directory, used to find the `grok login` session. `""` means `$GROK_HOME`, else `~/.grok`. |
| `callTimeoutMs` | number, >= 0 | `0` | Timeout for one call. `0` means no timer; the host's hook timeout is the limit. |
| `fallbackToClaude` | boolean | `false` | When the Grok login is missing or expired (`http` and `cli` transports), plan with Claude instead; the plan's model line then reads `claude:<model> [configured fallback · grok unavailable]`. When `false`, the prompt is not planned and the hook reports ``Prompt Uplift skipped · Grok 4.7 login required (run `grok login`)``. This applies on Grok Build under `auto` too. |
| `shuntBaseUrl` | http(s) URL | `""` | Base URL of your gateway for `shunt`; `/v1/messages` is appended. There is no built-in gateway: with `transport: "shunt"` and this key empty, the prompt is not planned and nothing is sent. The hook reports ``Prompt Uplift skipped · grok:unresolved [transport-incompatible]``, and no rows are created. Claude is not used instead: `fallbackToClaude` only applies to a missing Grok login. |
| `shuntModel` | string | `""` | Model name sent to the gateway. `""` sends `model`. |
| `shuntMaxTokens` | integer, > 0 | `8192` | `max_tokens` for `shunt` calls. |

The `http` and `cli` transports need `grok login`. `shunt` does not; the gateway owns the upstream credentials.

### `muse`: the Muse engine

The Muse engine runs the `muse` CLI headless (`muse exec --json`). It uses your existing Muse login. Each call is one agent turn with the shell, file writes and web tools disabled. Used when the engine resolves to Muse: on Muse Code by default, or anywhere with `think.engine` set to `"muse"` (or `bin/ultrathink grok engine muse` on that host). See [Choose an engine](how-to/choose-engine.md).

| Key | Type | Default | Meaning |
|---|---|---|---|
| `bin` | string | `"muse"` | The `muse` binary. |
| `model` | string | `"muse-spark-1.3-contributor"` | Model id passed as `--model`. `""` omits the flag and the CLI's session default answers. |
| `reasoningEffort` | `"none"`, `"minimal"`, `"low"`, `"medium"`, `"high"`, `"xhigh"`, `"max"` or `"ultra"` | `"high"` | Reasoning effort passed as `--reasoning-effort`. |
| `callTimeoutMs` | integer, >= 0 | `0` | Timeout for one call. `0` means no timer. |

### Host defaults

With `think.engine` set to `"auto"` (the default), each host plans with its own engine:

| Host | Engine | Model |
|---|---|---|
| Claude Code | Claude | `claude.model` (`"sonnet"`) |
| Hermes Agent | Chosen by the session model's family | The Claude, Grok or Muse route, picked from the model id Hermes sends; Claude when the family is unknown. The route then uses its own model key. |
| Omp | Native | The session's own live model, called inside Omp through Omp's own provider and login. See [`models`](#models-planning-model-selection). |
| Grok Build | Grok | `grok.model` (`"grok-4.7"`) |
| Muse Code | Muse | `muse.model` (`"muse-spark-1.3-contributor"`) |

On Omp, `auto` plans natively. ultrathink copies the session's live model once per prompt and runs the uplift, the graph, every node fill and the clarifying questions on that copy, through Omp's own provider and login. Nothing is read from Omp's saved session history, and the model is not mapped to a Claude, Grok or Muse family. When no model can be used, the prompt goes through unplanned and the reason is shown (see [the four states](how-to/choose-engine.md#planning-model-states)). A named engine (`think.engine`, or `bin/ultrathink grok engine …` for Omp) opts Omp out of native planning and uses that engine's CLI route. Omp's auxiliary helpers, the ship done check and the Teachable Moments distiller, are never native: they use the Claude CLI route under `auto`, or the named engine.

Native Omp planning also snapshots the session's thinking level once per flight and uses it for every planning stage. `off` uses Omp's reasoning-disable option; `inherit`, an unset level, or an older host without the capability leaves provider options unset. There is no hidden low-effort default, and the CLI-route effort settings do not control native planning. Changing the session level invalidates a reused flight at the next planning observation.

Native Omp planning has no outer planning deadline by default: an omitted or zero factory deadline creates no outer flight timer, and the 25-second handoff is delivery-only — it switches a slow plan to a pending note plus one eventual aside without cancelling, lowering effort, changing route, or retrying. That removes only the default outer flight timer. The shared explicit whole-planning budget (`claude.budgetMs`) still applies when configured, keeping its plan-built-so-far semantics; the CLI per-call timers (`callTimeoutMs`) still bound their CLI routes; and the independent service and hook limits on the other hosts are unchanged.

Hermes sends its session's model id, and ultrathink picks the Claude, Grok or Muse route from its family. An unknown model (Kimi included, until it gets an engine) plans with Claude. The id itself is never sent as the wire model.

Claude replaces a selected Grok route only through the two explicit, labeled user switches: `grok.fallbackToClaude: true` (HTTP/CLI login missing or expired) and `grok.enabled: false` (documented ‘forces Claude even when Grok is selected’). Without them, a missing or expired Grok login skips planning with the unchanged `GROK_LOGIN_REQUIRED` notice. Naming `think.engine: "claude"` is a deliberate engine choice, not a replacement.

The notice reads ``Prompt Uplift skipped · Grok 4.7 login required (run `grok login`)``. Set `think.engine` to a named engine to plan with one engine on every host. Teachable Moments are stored per host (see [`teach`](#teach-teachable-moments)), so every host keeps its own lessons whichever engine it plans with.

### Route defaults

The CLI routes take their built-in model from one version-controlled map, `ROUTE_DEFAULT_MODELS` in `src/route-defaults.ts`. It has one entry per route, and each entry can be changed on its own without touching the resolution logic:

| Route | Built-in model | Key that replaces it |
|---|---|---|
| `claude` | `sonnet` | `claude.model` |
| `grok` | `grok-4.7` | `grok.model` (on `shunt`, a non-empty `grok.shuntModel` is sent instead) |
| `muse` | `muse-spark-1.3-contributor` | `muse.model` |

- Unset in every config file, a route uses its map entry. The record says `default`, source `route-default`, and the label reads, for example, `claude:sonnet [route default]`.
- Set in any config file, the value is an override (`override`, source `engine-model`), even when it equals the built-in model.
- `""` for `claude.model` or `muse.model` omits `--model`, so the CLI's own default model answers: `claude:CLI default (model unobserved)`. A blank `grok.model` or `grok.shuntModel` is ignored, as before.
- Nonblank legacy model and shunt-alias values retain leading or trailing control characters for `selector-invalid` rejection before auth or execution; trimming cannot turn an invalid selector into a valid target. Whitespace-only values keep the clearing and lower-pin rules above.
  Omp's private flight identity uses that same normalization: changing a shunt alias from valid to control-invalid cancels the old plan, and correcting an invalid alias starts a fresh flight. Plain surrounding spaces and whitespace-only absence remain equivalent.

The map is keyed by route, not by provider. Native Omp planning never reads it: its defaults come from Omp (see below).

### `models`: planning model selection

Per-host model choices and per-provider defaults. Every layer may set them, the project file included.

| Key | Type | Default | Meaning |
|---|---|---|---|
| `models.hosts.<host>.model` | string | unset | The model to plan with on that host. `<host>` is `claude-code`, `grok-build`, `hermes`, `muse` or `omp`; other keys are ignored. On Omp under `auto` it is a selector that Omp resolves, such as a model id, `provider/id` or a role; a selector that does not resolve leaves the prompt unplanned and is never replaced by another model. On the CLI routes it is the wire model sent instead of the engine's own model key. |
| `models.hosts.<host>.provider` | string | unset | On Omp under `auto`: the exact provider id the model must come from. Without a `model`, a usable live model from that provider is kept; otherwise that provider's default is used. On the CLI routes no provider can be bound, so a provider here leaves the prompt unplanned (`transport-incompatible`). |
| `models.providerDefaults.<provider>` | string | none | Omp only: the model to plan with for that exact provider id when the session's own model cannot be used. Without an entry, the default of Omp's installed catalog for that provider is used. |

How these keys merge:

- A blank value (`""` or only whitespace) in a later file clears the earlier one. A cleared host model or provider restores the default resolution; a cleared `providerDefaults` entry restores the catalog default.
- An absent, `null` or wrong-type value keeps the earlier value. Surrounding whitespace is trimmed.
- A value that contains a control character is kept as written and reported as `selector-invalid` when the prompt is planned; it is never sent anywhere.
- Only own keys and own host `provider`/`model` fields merge: `__proto__`, `constructor` and `prototype` are skipped, inherited selectors and getters are ignored, and an absent or inherited field keeps its lower-layer pin.
- The keys select models Omp already has. They cannot define an endpoint, a header or a credential.

On Omp under `auto`, the planning model is chosen in this order, and the first match wins:

1. A non-empty `models.hosts.omp.model`, resolved by Omp (and required to come from `models.hosts.omp.provider` when that is set): `override`.
2. The session's live model, when Omp can use it for a plain text completion: `detected`.
3. The default for the live model's provider (or for `models.hosts.omp.provider`): `models.providerDefaults[<provider>]`, else Omp's installed catalog default for that provider. The model must come from exactly that provider, and a catalog default must be exactly that id. This is `default`, or `override` when a provider constraint made ultrathink pick it.
4. Otherwise `unresolved`, with the reason.

A failed `models.hosts.omp.model` or `providerDefaults` entry never falls through to the next tier. The catalog default is the per-provider default of the `@oh-my-pi/pi-catalog` package bundled with your Omp, so it changes when you update Omp. It is not a lookup of the provider's newest model. The states, sources and reasons are in [Choose the planning engine](how-to/choose-engine.md#planning-model-states).

Example: on Omp, always plan with a model from one provider. The session's own model is used when it comes from that provider and Omp can use it; otherwise the provider's configured default is used.

```json
{
  "models": {
    "hosts": { "omp": { "provider": "<provider id>", "model": "" } },
    "providerDefaults": { "<provider id>": "<model id or role>" }
  }
}
```

### `notion`: Notion tracking

| Key | Type | Default | Meaning |
|---|---|---|---|
| `dataSourceUrl` | string | `""` | The `collection://<data source id>` data source of the tracking database. `""` means Notion tracking is not configured and Notion is never contacted. See [Set up Notion](how-to/set-up-notion.md). |

### `linear`: Linear tracking

| Key | Type | Default | Meaning |
|---|---|---|---|
| `team` | string | `""` | The Linear team that issues and sub-issues are created in. `""` means Linear tracking is not configured and Linear is never contacted. See [Set up Linear](how-to/set-up-linear.md). |

### `track`: row creation by the planner

| Key | Type | Default | Meaning |
|---|---|---|---|
| `enabled` | boolean | `true` | The planner creates the Linear and Notion rows before the agent sees the prompt. When `false`, the planner creates none and the `ultrathink-kickoff` skill creates them instead. On Hermes the planner never creates rows, whatever this says; kickoff creates them all. `/ultrathink-track off\|on` overrides this per host. Has no effect when neither tracker is configured. |
| `budgetMs` | number, > 0 | `60000` | Time limit for the planner's whole row-creation run, including credential lookup. Rows not created in time are left for kickoff. |
| `concurrency` | number, >= 1 | `6` | Row-creation calls that run in parallel. Rounded down. |

### `ship`: PR, review and merge

Ship is opt-in. With the defaults, no skill run ever pushes a branch, opens a pull request or merges. See [Ship](ship.md) for the flow and [Ship with Greptile](how-to/ship-with-greptile.md) for setup.

| Key | Type | Default | Meaning |
|---|---|---|---|
| `enabled` | boolean | `false` | Tell the agent to run `ultrathink-ship` after a matching skill run: the plan gets a Ship section and the end-of-run nudge fires. `bin/ultrathink-ship` still works when you run it by hand with this off. |
| `autoMerge` | boolean | `false` | Allow `bin/ultrathink-ship merge`. When `false`, `merge` refuses (`autoMerge disabled`) and `run` stops once the PR is ready, with `next: "autoMerge disabled: merge manually"`. When `true` and `judge` is `"gate"`, the done assessment also requires an engine judge. |
| `judge` | `"gate"` or `"advisory"` | `"gate"` | What the LLM done judge decides. `"gate"`: the judge must say done with a confidence of at least 0.7 before `pr` opens a PR. `"advisory"`: only the deterministic rules gate `done`; the judge's verdict is recorded in the assessment and shown in the PR body, and a failed or missing judge never blocks. Either way the merge gate below is unchanged. See [Done assessment](ship.md#done-assessment). |
| `skills` | array of non-empty strings | `["gsd-"]` | Skill name prefixes that trigger ship. `[]` matches every skill run, and every planned prompt gets the ship instruction. |
| `minScore` | number, 1 to 5 | `5` | Lowest Greptile confidence score that may merge. 5 is Greptile's maximum ("5/5"). |
| `requireNoComments` | boolean | `true` | Refuse to merge while the head review has open comments. |
| `maxRounds` | number, >= 1 | `5` | Completed Greptile reviews below `minScore` or with open threads before the ship is blocked. Failed and timed-out reviews don't count (see `reviewRetries`). Rounded down. |
| `mergeMethod` | `"squash"`, `"merge"` or `"rebase"` | `"squash"` | Merge method. When the repository does not allow it, the first allowed method is used and the output says so. |
| `deleteBranch` | boolean | `false` | After the merge, delete the remote branch with an explicit refspec, check out and fast-forward the base branch, then delete the local branch with `git branch -d`. The local branch is force-deleted (`-D`) only when its tip is exactly the merged head. When `false`, branches are left alone. |
| `greptileOrganization` | string | `""` | Greptile organization id or handle, passed as `organization` on every Greptile MCP call. `""` lets Greptile pick, which works for accounts in one organization. An account in several organizations needs it: without it, the review is `blocked` with a reason that names this key and the candidates. |
| `reviewTimeoutMs` | number, >= 1 | `1200000` | How long a review of one head commit may stay pending before it counts as timed out (20 minutes). A timed-out review is re-triggered like a failed one (see `reviewRetries`). Rounded down. |
| `reviewRetries` | integer, >= 0 | `3` | A failed Greptile review (Greptile FAILED/ERROR/SKIPPED, no score, CLI failure) or one pending past `reviewTimeoutMs` is re-triggered on the next `review` call, up to this many times per head commit; then the ship blocks with a PR comment. These never count toward `maxRounds`. `0` blocks on the first failure. Rounded down. |
| `pollMs` | number, >= 1 | `20000` | First interval between review and merge status checks. It grows by 1.5 times per check, up to 60 seconds. Rounded down. |
| `waitMs` | number, >= 1 | `100000` | Longest one `review` or `merge` call blocks before it returns `pending` or `waiting: true` (100 seconds). `run` merges within what is left of its own `waitMs` after the review. Rounded down. |
| `mergeTimeoutMs` | integer, >= 1 (ms) | `3600000` | After the head's review passed, `merge` keeps retrying (pending CI, mergeability not computed, unreadable PR state or threads, transient GitHub errors) within each call up to `waitMs`, returning `waiting: true` and `next: "run merge again: …"` when the call's time runs out; the agent runs `merge` again. Past `mergeTimeoutMs` (60 minutes) on one head commit, or on a terminal GitHub refusal (missing permission, requested changes, a closed PR; a branch-protection hold such as a missing approval is retried until the bound instead), the ship blocks and the PR comment lists the attempt history. Conflicts, failing CI, a moved head or a review below 5/5 go back to the agent (`next`), never merge. Rounded down. |

`ULTRATHINK_SHIP=0` turns the ship instruction and nudge off for one process whatever `ship.enabled` says.

The merge gate never weakens, and `judge: "advisory"` does not change it: a completed Greptile review of the exact PR head with a score of at least `minScore` (default 5, Greptile's maximum) and no open threads, an open mergeable PR, and CI neither pending nor failing. A PR merged outside the flow without such a review is reported blocked, never recorded as a ship merge; agents must never merge any other way (no `gh pr merge`, no web UI). Every review result and merge outcome is recorded in `ship.attempts` in the session record (newest 50), shown by `bin/ultrathink-ship status`.

### `substrate`: Agent Substrate brief

Agent Substrate is an optional service that tells the planner what other agents already did in the repository. ultrathink asks it for a brief before it builds the Graph of Thought, and adds the answer to the plan under `## Agent Substrate brief`. Once the plan and its session record are written, ultrathink tells the substrate the plan exists: one `note` event carrying the Graph ID, which the substrate adopts as its correlation key, so work other agents do under that Graph ID joins the same trail. The event holds no text of your prompt, the spec or the plan (see [Privacy](privacy.md)). Nothing is requested unless a URL is set.

| Key | Type | Default | Meaning |
|---|---|---|---|
| `url` | http(s) URL | `""` | Base URL of your Agent Substrate server. ultrathink sends `POST <url>/brief` with the repository (`owner/repo`), the branch and the host name, and, after planning, `POST <url>/events` with the Graph ID, the session id, the host name, the repository, the branch and the node count. `""` means the service is never contacted. `SUBSTRATE_URL` wins over this key, and `SUBSTRATE_DISABLED=1` turns both off. Ignored when `backend` is `gateway`. |
| `backend` | `"direct"` or `"gateway"` | `"direct"` | `"direct"` is the client above. `"gateway"` calls the desk gateway (see [`gateway`](#gateway-desk-gateway)). User files only. `ULTRATHINK_SUBSTRATE_BACKEND` overrides it. `ULTRATHINK_GATEWAY=0` forces `"direct"`. |

Each request times out after 1.5 seconds (`SUBSTRATE_TIMEOUT_MS` changes that). A missing, slow or failing server never blocks a prompt: the plan is built without the brief, and a refused or lost event is dropped. The event goes out after planning, so a server that accepts the connection and never answers adds up to one timeout before the plan is returned. `bin/ultrathink status` shows the `Substrate:` line with the URL in use and where it came from.

### `pstack`: Cursor bridge

Opt-in instructions that tell Cursor, on a `/gsd-*` prompt, to read the matching pstack skills alongside that GSD step. Off until you set `enabled`. The planning engine never sees this section. The hook writes nothing and sends nothing off the machine. Walk-through: [Run pstack skills beside GSD in Cursor](how-to/use-pstack-with-cursor.md).

| Key | Type | Default | Meaning |
|---|---|---|---|
| `enabled` | boolean | `false` | Turn the bridge on. Only a user file counts: the same key in `<project>/.claude/ultrathink.json` is ignored. `ULTRATHINK_PSTACK=0` forces it off for one process. |
| `cursorDir` | absolute path | unset | Cursor directory whose plugin cache and `hooks.json` the hook and doctor use. Unset means `$ULTRATHINK_PSTACK_CURSOR_DIR`, else `~/.cursor`. A relative path is ignored. User file only. |
| `mapping` | object | the built-in mapping | Per-stage skill names. Stages are `discuss`, `plan`, `execute` and `review`. A listed stage replaces that stage's default list; unknown stage names and non-strings are dropped. Defaults: `discuss` → `how`; `plan` → `architect`, `arena`; `execute` → `tdd`; `review` → `interrogate`, `no-comments`. `/gsd-autonomous` uses every stage. User file only. |
| `contextCapChars` | integer, >= 1 | `2000` | Longest instruction block, in characters. The hook drops skills from the right until the block fits, and injects nothing when even one skill cannot fit. `0`, a negative number or a non-integer is ignored. User file only. |

The hook does not merge config layers. It reads the first file that exists and is JSON: `$ULTRATHINK_CONFIG_DIR/config.json` when that variable is set, otherwise `${XDG_CONFIG_HOME:-~/.config}/ultrathink/config.json` and then `${CLAUDE_CONFIG_DIR:-~/.claude}/ultrathink.json`. Put `pstack` in whichever of those the hook actually reads (the first one that parses). `ultrathink doctor` names that file as the deciding source.

### `decisions`: Jev decisions (OpenRouter Decisions API)

Decisions are always on. With a Jev key, ultrathink asks Jev, a decision model from TypeSafe, one yes/no question at each active decision point, over OpenRouter's Decisions API (`https://openrouter.ai/api/alpha/decisions`, marked alpha by OpenRouter) or the Vercel AI Gateway's evaluation-model endpoint (`https://ai-gateway.vercel.sh/v4/ai/evaluation-model`), picked by `provider` below. Vercel serves Jev only: engine selection and the Graph of Thought never reference it. Jev answers with a probability P, and the thresholds below turn P into an action. Jev is asked only after every deterministic rule has run and left the action open, and it never merges, never demotes a blocking question and never overrides a rule gap. Any failure fails open: the point behaves exactly as it does with Decisions off. See [Use Jev decisions](how-to/use-jev-decisions.md) for a walk-through and [What leaves your machine](privacy.md#jev-decisions-openrouter) for what is sent.

| Key | Type | Default | Meaning |
|---|---|---|---|
| `enabled` | boolean | `true` | Always on; the value in files is ignored, in every layer. Kept for compatibility. `ULTRATHINK_DECISIONS=0` in the environment is the only way to turn every point off. |
| `provider` | `"auto"`, `"openrouter"` or `"vercel"` | `"auto"` | Which rail Jev calls take. `auto` uses Vercel when a Vercel key is present (stored `vercel` key or `AI_GATEWAY_API_KEY`), else OpenRouter. `"openrouter"` and `"vercel"` pin that rail; without its key, no point sends a request. Merges as usual in every file. |
| `model` | non-empty string | `"~typesafe/jev-latest"` | Decisions model id or alias. The alias follows the latest Jev; set `"typesafe/jev-1.13"` to pin the version the default thresholds were probed on. On the OpenRouter rail the model is sent as-is; on the Vercel rail the default alias is sent as `typesafe-ai/jev` in the `ai-model-id` header and an explicit model verbatim. Every decision records the resolved model, for example `typesafe/jev-1.13-20260917`. |
| `points` | array of `"plan"`, `"ship"`, `"knowledge"`, `"blocking"`, `"teachable"`, `"skillworthy"` | `["plan", "ship", "knowledge", "blocking", "teachable", "skillworthy"]` | Which decision points ask Jev. Unknown names and repeats are dropped; `[]` means none. The project file can only remove points: its list is intersected with the one from the earlier files. |
| `timeoutMs` | number, > 0 and <= 30000 | `3000` | Total budget for one decision in milliseconds, the retry included. |
| `zdr` | boolean | `true` | On the OpenRouter rail, send `provider: {"zdr": true, "data_collection": "deny"}`, so OpenRouter routes only to zero-data-retention endpoints and denies data collection. `false` sends no provider preferences. In the project file only `true` counts. The Vercel rail has no such fields, so this key does not affect it. |
| `planSkipBelow` | number, 0 to 1 | `0.2` | Plan gate: a message is not planned when P(`plan_worthy`) is below this. |
| `shipVetoAtOrBelow` | number, 0 to 1 | `0.2` | Ship veto: in gate mode, an LLM "done" becomes not done when P(`complete`) is at or below this and the patch Jev saw was not truncated. In advisory mode nothing is blocked: a P(`complete`) at or below this on an untruncated patch is recorded as `advise-veto`, whatever the judge said. |
| `shipApproveAt` | number, 0 to 1 | `0.7` | Ship verdict when there is no usable LLM verdict (gate mode with `ship.autoMerge` off): done when P(`complete`) is at or above this, not done below it. With `ship.autoMerge` on, Jev never stands in for the LLM judge. |
| `groundedAt` | number, 0 to 1 | `0.8` | Knowledge check: a question the Greptile knowledge base settled stays settled when P(`supported`) is at or above this; below it, the question is asked after the clarifier's own questions while fewer than `hitl.maxQuestions` are open, and dropped when no slot is left. |
| `blockingAt` | number, 0 to 1 | `0.5` | Blocking check: a non-blocking question becomes blocking when P(`risky`) is at or above this. A blocking question is never made non-blocking. |
| `teachableBelow` | number, 0 to 1 | `0.3` | Teachable lesson: a candidate is dropped before it is stored when P(`teachable`) is below this. P equal to this keeps it. |
| `teachableAutoAt` | number, 0 to 1 | `0.8` | Auto capture confirms a candidate only when P(`teachable`) is at or above this, and only when the candidate's own confidence is also at least 0.8. Below this, the candidate stays for a human to confirm. Jev never confirms a lesson the confidence bar would have held. |
| `skillworthyAt` | number, 0 to 1 | `0.5` | `promote --due` and automatic promotion skip a lesson when P(`skillworthy`) is below this. An explicit `teach promote <id>` does not ask this point. |

How Decisions work:

- `ULTRATHINK_DECISIONS=0` in the environment turns every point off for that process, whatever the config says: no request, no record, no plan-skip notice and no `Decisions ·` segment. `bin/ultrathink status` then shows `Decisions: off (ULTRATHINK_DECISIONS=0)`. It is the only off switch.
- The project file can drop points, set `zdr` to `true`, and change `provider`, `model`, `timeoutMs` and the thresholds, but it cannot add points or turn `zdr` off. Points need a key to send anything, and keys live only in your credential store and environment, so a repository you open sends nothing to either rail unless you stored or set a key.
- The key comes from the credential store (`bin/ultrathink-mcp auth set-key vercel --stdin` or `bin/ultrathink-mcp auth set-key openrouter --stdin`), else from `AI_GATEWAY_API_KEY` or `OPENROUTER_API_KEY`. The stored key wins on its rail. Without a key for the resolved rail, no point sends a request, and `bin/ultrathink status` says so.
- There is no config key for the endpoint. Any other key under `decisions` (a `url` or `endpoint`, for example) is ignored, so a project file cannot send your key anywhere else. Only `ULTRATHINK_DECISIONS_URL` in the environment changes the endpoint, and only on the OpenRouter rail, and only to an `https://openrouter.ai/…` URL or a loopback URL (see [Environment variables](#environment-variables)). The Vercel endpoint is fixed. A request never follows an HTTP redirect.
- `teachable` asks "Is this candidate a reusable lesson that a future agent on this repository would otherwise have to rediscover?" It runs when `observe` distills candidates and Decisions are on. Below `teachableBelow` the candidate is not stored. In `auto` capture, confirmation also needs P at or above `teachableAutoAt`. `skillworthy` asks "Does this lesson describe a repeatable procedure or rule worth a standing skill?" `promote --due` and automatic promotion leave a moment out when P is below `skillworthyAt`. Any failure of either point behaves as with that point off: the candidate is kept, and auto confirmation follows the confidence bar alone.
- The other four points: `plan` can skip planning for a message the rules would plan; `ship` can veto an LLM "done", or decide when there is no usable LLM verdict and `ship.autoMerge` is off; `knowledge` can take back a question the knowledge base settled, which is then asked if a question slot is free; `blocking` can make a non-blocking question blocking. A skill invocation (every `/gsd-*` run included) and a message that starts with `uplift:` make no `plan` decision, but their clarifying questions can still get `knowledge` and `blocking` decisions, and each ship `assess` whose rule checks pass makes one `ship` decision, GSD runs included. A message the deterministic rules skip makes none.
- The six questions, as sent (`type: "noul"`): `plan` asks whether `message`, read with `recent_conversation`, starts new multi-step engineering work; `ship` asks whether `patch` fully delivers `request` and every item in `acceptance_criteria`; `knowledge` asks whether `answer` is a correct answer to `question` according to `document`; `blocking` asks whether a wrong `default` for `question` while doing `task` would cause damage that is hard to undo; `teachable` and `skillworthy` are the two sentences above.
- One decision makes at most one retry, only for a network error or HTTP 408, 429, 500, 502, 503, 524 or 529, and only when at least 500 ms of `timeoutMs` remain. It honours `Retry-After` when that fits the budget.
- A request whose estimated size is over 28 000 tokens is not sent; it fails locally as `too-large`.
- Each decision is recorded without any of the state it was asked about: point, resolved model, probability, threshold, action, latency, attempts, cost and error kind. You see it in the summary (`Decisions · plan 0.97`, with `claude.echo` on), the plan-skip notice, the session record's `decisions` field, the ship assessment's `decision`, the pull request's `- Jev:` line and, with `ULTRATHINK_DEBUG=1`, one stderr line per decision. `bin/ultrathink status` shows the `Decisions:` line.

The default thresholds were set from probes on `typesafe/jev-1.13-20260917`. Tune them on your own cases with `bin/ultrathink decisions probe` (see [Commands](commands.md#binultrathink-decisions)).

### `gateway`: desk gateway

Used only when `hindsight.backend`, `ragflow.backend` or `substrate.backend` is `"gateway"`. A project file cannot set this section. The seat token is not a config key.

| Key | Type | Default | Meaning |
|---|---|---|---|
| `url` | string | `""` | Gateway origin. User files only. Empty falls back to `DESK_GATEWAY_URL`. Same URL rules as `hindsight.url`. The client posts to `<url>/mcp/<seat>`. |
| `seat` | string | `"lead"` | Seat path segment. Must match `^[a-z][a-z0-9-]{0,31}$`. `DESK_GATEWAY_SEAT` overrides it when that value matches. |
| `timeoutMs` | integer, 1 to 120000 | `8000` | Budget for one tool call. `DESK_GATEWAY_TIMEOUT_MS` overrides it when it is in range. |

The token comes from the credential store, provider `desk-gateway` (an `api_key`, or an OAuth `accessToken`), else `DESK_GATEWAY_TOKEN`. It is sent only as `Authorization: Bearer` on that one request, and never printed. `ULTRATHINK_GATEWAY=0` forces every integration back to `"direct"`.

`bin/ultrathink status` then prints `Hindsight: gateway · ready · <origin> · seat <seat> · token from <store|DESK_GATEWAY_TOKEN>`, or `gateway · unready` with the reason (no URL, bad URL, no token). RAGFlow and Substrate use the same shape. `bin/ultrathink hindsight check` and `bin/ultrathink ragflow check` probe the gateway; `not_configured`, `unknown_tool`, an `error`/`reason` pair and a timeout are one-line degraded or unready results.

### `hindsight`: Hindsight memory server

Hindsight is opt-in storage for confirmed Teachable Moments. With the defaults, nothing is contacted. See [Connect Hindsight](how-to/connect-hindsight.md) (`docs/how-to/connect-hindsight.md`).

| Key | Type | Default | Meaning |
|---|---|---|---|
| `enabled` | boolean | `false` | Opt-in. When `false`, no request is made. Only a user file can set it to `true`: in the project file only `false` counts. `ULTRATHINK_HINDSIGHT=0` (the exact string) turns it off whatever this says, and is checked before `enabled`. |
| `url` | string | `""` | Base URL of the Hindsight API. User files only. Empty falls back to `HINDSIGHT_API_URL`. An empty string does not clear a URL an earlier file set. A value is kept as written; a bad one is reported on the status line, not silently dropped. |
| `bank` | string | `"ultrathink"` | Bank that holds ultrathink's records. User files only. Must match `^[A-Za-z0-9][A-Za-z0-9._-]{0,63}$`; anything else is ignored and the earlier value stays. |
| `timeoutMs` | integer, 1 to 120000 | `5000` | Budget in milliseconds for health, bank, document and recall requests. |
| `retainTimeoutMs` | integer, 1 to 120000 | `15000` | Budget in milliseconds for one retain. |
| `backend` | `"direct"` or `"gateway"` | `"direct"` | `"direct"` uses the Hindsight API and its key. `"gateway"` uses the desk gateway and does not read a Hindsight key. User files only. `ULTRATHINK_HINDSIGHT_BACKEND` overrides it. `ULTRATHINK_GATEWAY=0` forces `"direct"`. |

The key is not a config key. It comes from the credential store, provider `hindsight` (`bin/ultrathink-mcp auth set-key hindsight --stdin`), else `HINDSIGHT_API_KEY`, else `HINDSIGHT_API_TOKEN`. The stored key wins. `hindsight` is an API-key provider, not an MCP server: `serve`, `check` and `auth login` refuse it and name `auth set-key hindsight --stdin`.

A URL is accepted only as `https`, or as `http` on `localhost`, `127.0.0.1`, `[::1]`, a name ending in `.ts.net`, or an address in `100.64.0.0/10`. A user name, password, query or fragment is refused. The status line shows the origin only, never a path and never the key. The key is sent only on `/v1/**`, and only to a URL that passed that check. A request never follows a redirect.

The client keeps the bank in `chunks` extraction mode (`retain_extraction_mode: chunks`). That stores lesson text as written and does not call a server-side LLM. Do not switch the bank to another mode, and do not enable verbatim or reflect: a server with no LLM cannot retain in those modes, and the client sets `chunks` itself on `ensureBank`.

`bin/ultrathink status` prints a line that starts with `Hindsight: `:

- `Hindsight: off (ULTRATHINK_HINDSIGHT=0)`
- `Hindsight: off (opt-in: set hindsight.enabled)`
- `Hindsight: on · no URL (set hindsight.url or HINDSIGHT_API_URL)`
- `Hindsight: on · bad URL (<reason>)`
- `Hindsight: on · no key (run bin/ultrathink-mcp auth set-key hindsight --stdin, or set HINDSIGHT_API_KEY)`
- `Hindsight: on · <origin> · bank <bank> · key from <store|HINDSIGHT_API_KEY|HINDSIGHT_API_TOKEN>`

The no-key line names `HINDSIGHT_API_KEY`. `HINDSIGHT_API_TOKEN` is also accepted, after the stored key and `HINDSIGHT_API_KEY`, and the ready line then says `key from HINDSIGHT_API_TOKEN`.

### `ragflow`: RAGFlow document search

RAGFlow is opt-in. With the defaults, nothing is contacted. When `ground` is on and the service is ready, excerpts from the configured datasets are added to the plan as untrusted evidence, bounded by `groundChars`, fail-open, and recorded on the session. The section starts with `## Documents (RAGFlow)`. See [Connect RAGFlow](how-to/connect-ragflow.md) (`docs/how-to/connect-ragflow.md`).

| Key | Type | Default | Meaning |
|---|---|---|---|
| `enabled` | boolean | `false` | Opt-in. When `false`, no request is made. Only a user file can set it to `true`: in the project file only `false` counts. `ULTRATHINK_RAGFLOW=0` (after trim) turns it off whatever this says, and is checked before `enabled`. |
| `url` | string | `""` | Base URL of the RAGFlow origin. User files only. Empty falls back to `RAGFLOW_URL`. An empty string does not clear a URL an earlier file set. A bad URL is kept as written and reported, not silently dropped. |
| `datasetIds` | array of non-empty strings, at most 20 | `[]` | Datasets to search. User files only. Empty means every dataset the key can see. Every element must be a non-empty string, or the whole array is ignored. Duplicates are dropped. |
| `topK` | integer, 1 to 20 | `5` | Chunks returned per search (`page_size`). |
| `similarityThreshold` | number, 0 to 1 | `0.2` | RAGFlow `similarity_threshold`. |
| `timeoutMs` | integer, 1 to 120000 | `8000` | Budget in milliseconds for one request. |
| `ground` | boolean | `false` | Add retrieved excerpts to the planner's context. A project file can only turn this off. Off means no request, even when `enabled` is true. |
| `groundChars` | integer, 500 to 8000 | `3000` | Cap on the characters of excerpts added to the planner's context. |
| `backend` | `"direct"` or `"gateway"` | `"direct"` | `"direct"` uses the RAGFlow API and its key. `"gateway"` uses the desk gateway and does not read a RAGFlow key. User files only. `ULTRATHINK_RAGFLOW_BACKEND` overrides it. `ULTRATHINK_GATEWAY=0` forces `"direct"`. |

The key is not a config key. It comes from the credential store, provider `ragflow` (`bin/ultrathink-mcp auth set-key ragflow --stdin`), else `RAGFLOW_API_KEY`. The stored key wins. `ragflow` is an API-key provider, not an MCP server: `serve`, `check` and `auth login` refuse it and name `auth set-key ragflow --stdin`.

The URL rules are the same as [`hindsight`](#hindsight-memory-server): `https`, or `http` only for loopback, `*.ts.net` and `100.64.0.0/10`, with no user name, password, query or fragment. The status line shows the origin only.

Health is a one-row dataset listing, `GET /api/v1/datasets?page=1&page_size=1`. Never request `/system/healthz`, `/v1/system/healthz` or `/api/v1/system/healthz`: on a deployment whose object storage is down, that route can block the API worker. `bin/ultrathink ragflow check` uses the datasets probe. The CLI ignores `ragflow.ground`, so the connection can be proven before grounding is turned on.

`bin/ultrathink status` prints a line that starts with `RAGFlow: `:

- `RAGFlow: off (ULTRATHINK_RAGFLOW=0)`
- `RAGFlow: off (opt-in: set ragflow.enabled)`
- `RAGFlow: on · no URL (set ragflow.url or RAGFLOW_URL)`
- `RAGFlow: on · bad URL (<reason>)`
- `RAGFlow: on · no key (run bin/ultrathink-mcp auth set-key ragflow --stdin, or set RAGFLOW_API_KEY)`
- `RAGFlow: on · <origin> · key from <store|RAGFLOW_API_KEY> · grounding on|off · <n> dataset(s) pinned` when `datasetIds` is non-empty, or `· all datasets` when it is empty

### `teach`: Teachable Moments

Teachable Moments are on by default: finished turns are distilled into lessons and recurring lessons become skills without a human step. With `enabled: false`, nothing is stored and nothing is recalled. See [Use Teachable Moments](how-to/use-teachable-moments.md) (`docs/how-to/use-teachable-moments.md`) and, on Hermes, [Teachable Moments on Hermes](how-to/teachable-moments-on-hermes.md) (`docs/how-to/teachable-moments-on-hermes.md`).

| Key | Type | Default | Meaning |
|---|---|---|---|
| `enabled` | boolean | `true` | Master switch. Only a user file can set it to `true`: in the project file only `false` counts. `ULTRATHINK_TEACH=0` (the exact string) turns it off for the process when this is `true`. |
| `capture` | `"explicit"`, `"observe"` or `"auto"` | `"auto"` | `explicit`: only `teach capture` (CLI, agent tool or slash command) creates moments. `observe`: hosts also hand finished turns to a detached `teach observe`, which stores local candidates. `auto`: a candidate whose confidence is at least 0.8 is confirmed and retained without a human step, unless Jev holds it (see `teachableAutoAt`). A project file can only lower the mode (`auto` to `observe` to `explicit`). |
| `recall` | boolean | `true` | Inject recalled lessons and skills into plans. Does nothing while `enabled` is false. A project file can only turn it off. The lessons section starts with `## Lessons from earlier work` and is framed as untrusted evidence; the skills section starts with `## Relevant skills`. |
| `recallLimit` | integer, 1 to 10 | `5` | Lessons per plan. |
| `recallChars` | integer, 500 to 8000 | `3000` | Cap on the characters of the lessons section. |
| `promoteAfter` | integer, 2 to 20 | `3` | Occurrences before a confirmed moment is offered as a skill. A confirmed `playbook` is offered without waiting for this count. |
| `autoPromote` | boolean | `true` | Install a due moment for the host that captured it, without a human step. User files only; a project file can only turn it off. Hermes, Muse and unknown hosts still only get a draft. Off is report-only: `teach promote --due` lists them. |
| `observeMinToolCalls` | integer, 0 to 50 | `4` | `observe` skips a turn with fewer tool calls than this. |
| `timeoutMs` | integer, 500 to 30000 | `2500` | Budget in milliseconds for the recall inside the planner. |

`ULTRATHINK_TEACH=0` is checked after `enabled`. While `enabled` is false the status line says `Teach: off (opt-in: set teach.enabled)` even if the variable is set. When `enabled` is true and the variable is `0`, the line is `Teach: off (ULTRATHINK_TEACH=0)`.

Lessons are written under the host state directory, `<stateDir>/teach/`: one JSON file per moment in `moments/`, pending Hindsight writes in `outbox/`, observe digests in `inbox/`, and skill drafts in `skill-drafts/<name>/SKILL.md`. `ULTRATHINK_STATE_DIR` is honored, and a path inside `.planning` is ignored. Nothing is written into `<cwd>/.planning` or a repository working tree. A Hindsight failure queues an outbox entry (backoff 1 minute, doubling, capped at 6 hours) and does not block the caller. `teach sync` drains the outbox.

Before anything is stored or sent, text is redacted. `Bearer` followed by a short English word is left alone (`the Bearer key`, `Bearer token rotation`). `Bearer` followed by a token is replaced with `[redacted]` when the token is at least 16 characters, or at least 6 characters and contains a digit. Trailing dots stay. See [Troubleshooting](troubleshooting.md#redaction).

`bin/ultrathink status` prints a line that starts with `Teach: `:

- `Teach: off (opt-in: set teach.enabled)`
- `Teach: off (ULTRATHINK_TEACH=0)`
- `Teach: on · capture <explicit|observe|auto> · recall on|off · <n> confirmed, <m> candidate · Hindsight <ready|off|no URL|bad URL|no key> · outbox <k>`

The confirmed/candidate counts and the outbox count are included when the status command knows the state directory, which `bin/ultrathink status` does. `Hindsight` here is the readiness word, not the `Hindsight:` line.

### `state`: session retention

| Key | Type | Default | Meaning |
|---|---|---|---|
| `retentionDays` | integer, 0 to 3650 | `0` | Days to keep session records (`sessions/<id>.json` and its `.xml`). `0` keeps everything forever. Above `0`, the scheduled prune removes sessions whose newest file is older than this. User files only: a project file cannot set it. |

#### Session retention

By default nothing is ever deleted: every session record stays in the state directory until you remove it. Those records hold your prompt and the plan, so you may want to trim them. Two ways:

- **On request.** `bin/ultrathink prune --older-than 30` removes sessions older than 30 days (`30d` also works). Add `--dry-run` to list candidates without changing them; a real run rechecks freshness and protection and skips records being written, since state can change after the preview. Without `--older-than` the command uses `state.retentionDays`; if neither gives a cutoff above 0 it exits 2 and deletes nothing. `--older-than` must be a whole number from 1 to 3650: a smaller cutoff is refused, so a typo cannot empty the directory. Exit codes: 0 done, 1 a file could not be removed (the file name and error code are printed, never content), 2 usage error or refused cutoff.
- **On a schedule, if you opt in.** With `state.retentionDays` above 0 in a user file, planning runs the same prune, best effort, at most once a day (it records the time in `<stateDir>/.last-prune`) and looking at no more than 500 directory entries per run. A failure never blocks a prompt. With the key unset nothing prunes by itself.

What a prune never removes:

- A session whose ship has a pull request that is neither merged nor blocked.
- The session `last.json` names and the session the plan carrier (`last-plan.json`) points to.
- Symlinks or Teachable Moments lessons under `teach/`. Session deletion only selects `sessions/<id>.json` and `sessions/<id>.xml`; narrowly recognized write/lock leftovers have the separate orphan rules below.

A prune also removes regular `*.tmp` and `*.lock` files older than one hour in `sessions/` or directly in the state directory. Lock deletion shares the writer's mutation guard and rechecks age before removal; a busy guard is skipped, and an active strict `last.json` lock whose PID is alive is never an orphan. Prepared `*.lock.guard.<pid>.<32-hex-nonce>.tmp` directories are removed only when their named PID is dead and they are empty or contain exactly their own empty owner marker; live owners and unrelated contents are preserved. Dry runs take no mutation guard and change nothing.

`prune` works on the current host's state directory. To prune another host's, set `ULTRATHINK_HOST=<host>`, for example `ULTRATHINK_HOST=omp bin/ultrathink prune --older-than 30 --dry-run`. The output lists session ids, sizes and ages, never prompt text.

## Full example

All keys are optional; write only the ones you change. This file shows every key. The values are the defaults, with these exceptions:

- `notion.dataSourceUrl` and `linear.team` hold placeholders. Replace them with your own values, or leave them `""` to keep tracking unconfigured.
- `grok.shuntBaseUrl`, `grok.shuntModel` and `substrate.url` are `""`, which is the default and means off. Set them only if you run those services.
- `ship.enabled`, `ship.autoMerge`, `ship.deleteBranch`, `hitl.knowledgeBase`, `hindsight.enabled`, `ragflow.enabled` and `ragflow.ground` are `false`, the opt-in defaults. `hindsight.url` and `ragflow.url` are `""`, which means those services are not contacted. `teach.enabled` and `teach.autoPromote` are `true` and `teach.capture` is `"auto"`: lessons and skills are created without a human step. `decisions.enabled` is `true`: Jev is always on, and the value is ignored.

```json
{
  "uplift": { "enabled": true, "skipTrivial": true, "maxChars": 0, "echo": true },
  "think": { "enabled": true, "minNodes": 5, "maxNodes": 8, "engine": "auto" },
  "hitl": { "enabled": true, "maxQuestions": 4, "knowledgeBase": false },
  "claude": {
    "bin": "claude",
    "model": "sonnet",
    "thinking": false,
    "settingSources": "",
    "callTimeoutMs": 0,
    "budgetMs": 0,
    "concurrency": 3,
    "echo": true
  },
  "grok": {
    "enabled": true,
    "transport": "http",
    "baseUrl": "https://cli-chat-proxy.grok.com/v1",
    "model": "grok-4.7",
    "reasoningEffort": "xhigh",
    "bin": "grok",
    "home": "",
    "callTimeoutMs": 0,
    "fallbackToClaude": false,
    "shuntBaseUrl": "",
    "shuntModel": "",
    "shuntMaxTokens": 8192
  },
  "muse": {
    "bin": "muse",
    "model": "muse-spark-1.3-contributor",
    "reasoningEffort": "high",
    "callTimeoutMs": 0
  },
  "models": { "hosts": {}, "providerDefaults": {} },
  "notion": { "dataSourceUrl": "collection://<data source id>" },
  "linear": { "team": "<your Linear team>" },
  "track": { "enabled": true, "budgetMs": 0, "concurrency": 6 },
  "ship": {
    "enabled": false,
    "autoMerge": false,
    "judge": "gate",
    "skills": ["gsd-"],
    "minScore": 5,
    "requireNoComments": true,
    "maxRounds": 5,
    "mergeMethod": "squash",
    "deleteBranch": false,
    "greptileOrganization": "",
    "reviewTimeoutMs": 1200000,
    "reviewRetries": 3,
    "pollMs": 20000,
    "waitMs": 100000,
    "mergeTimeoutMs": 3600000
  },
  "substrate": { "url": "" },
  "pstack": { "enabled": false, "contextCapChars": 2000 },
  "decisions": {
    "enabled": true,
    "provider": "auto",
    "model": "~typesafe/jev-latest",
    "points": ["plan", "ship", "knowledge", "blocking", "teachable", "skillworthy"],
    "timeoutMs": 3000,
    "zdr": true,
    "planSkipBelow": 0.2,
    "shipVetoAtOrBelow": 0.2,
    "shipApproveAt": 0.7,
    "groundedAt": 0.8,
    "blockingAt": 0.5,
    "teachableBelow": 0.3,
    "teachableAutoAt": 0.8,
    "skillworthyAt": 0.5
  },
  "hindsight": {
    "enabled": false,
    "url": "",
    "bank": "ultrathink",
    "timeoutMs": 5000,
    "retainTimeoutMs": 15000
  },
  "ragflow": {
    "enabled": false,
    "url": "",
    "datasetIds": [],
    "topK": 5,
    "similarityThreshold": 0.2,
    "timeoutMs": 8000,
    "ground": false,
    "groundChars": 3000
  },
  "teach": {
    "enabled": true,
    "capture": "auto",
    "recall": true,
    "recallLimit": 5,
    "recallChars": 3000,
    "promoteAfter": 3,
    "autoPromote": true,
    "observeMinToolCalls": 4,
    "timeoutMs": 2500
  },
  "state": {
    "retentionDays": 0
  }
}
```

Optional integrations, one small file each:

Plan with Grok through an Anthropic-compatible gateway you run:

```json
{
  "think": { "engine": "grok" },
  "grok": { "transport": "shunt", "shuntBaseUrl": "https://<your gateway host>", "shuntModel": "<model name your gateway expects>" }
}
```

Turn ship on, with merging and branch cleanup (all three are off by default):

```json
{ "ship": { "enabled": true, "autoMerge": true, "deleteBranch": true, "greptileOrganization": "<your Greptile organization>" } }
```

Ask an Agent Substrate server for a brief before each plan:

```json
{ "substrate": { "url": "https://<your substrate host>" } }
```

Read the repository's Greptile knowledge base before the clarifying questions. Store a Greptile credential first with `bin/ultrathink-mcp auth login greptile` (or `bin/ultrathink-mcp auth set-key greptile --stdin`); set `ship.greptileOrganization` only if your Greptile account is in several organizations:

```json
{ "hitl": { "knowledgeBase": true }, "ship": { "greptileOrganization": "<your Greptile organization>" } }
```

Ask Jev at the six decision points. No config is needed: Jev is always on, so storing a key is enough. Store a Vercel key with `bin/ultrathink-mcp auth set-key vercel --stdin` (or set `AI_GATEWAY_API_KEY`), or an OpenRouter key with `bin/ultrathink-mcp auth set-key openrouter --stdin` (or set `OPENROUTER_API_KEY`); with both stored, `auto` picks Vercel. `"model": "typesafe/jev-1.13"` pins the version the default thresholds were probed on, and `"provider": "openrouter"` pins the rail:

```json
{ "decisions": { "provider": "openrouter", "model": "typesafe/jev-1.13" } }
```

Store confirmed lessons in Hindsight. Put `url` and `bank` in a user file; the project file cannot set them. Store the key with `bin/ultrathink-mcp auth set-key hindsight --stdin` (or set `HINDSIGHT_API_KEY`). Do not put a production URL in a repository file. See [Connect Hindsight](how-to/connect-hindsight.md) (`docs/how-to/connect-hindsight.md`):

```json
{ "hindsight": { "enabled": true, "url": "https://<your hindsight host>", "bank": "ultrathink" }, "teach": { "enabled": true } }
```

Ground plans with RAGFlow excerpts. `ground` sends the prompt to RAGFlow, so only a user file can turn it on. Store the key with `bin/ultrathink-mcp auth set-key ragflow --stdin` (or set `RAGFLOW_API_KEY`). See [Connect RAGFlow](how-to/connect-ragflow.md) (`docs/how-to/connect-ragflow.md`):

```json
{ "ragflow": { "enabled": true, "url": "https://<your ragflow host>", "ground": true } }
```

## Environment variables

Every variable ultrathink reads, grouped by who sets it. Variables that expect `1` or `0` compare the exact string: `ULTRATHINK_SHIP=false` does nothing.

### Variables you may set

| Variable | Effect |
|---|---|
| `ULTRATHINK_UPLIFT=0` | Do not plan any prompt in this process. The `uplift:` prefix does not override it. Useful for automation and `claude -p` runs. |
| `ULTRATHINK_TRACK=0` | The planner creates no rows in this process. The `ultrathink-kickoff` skill still creates them through `track complete`. To stop all rows, use `/ultrathink-track off`. |
| `ULTRATHINK_SHIP=0` | No ship instruction in the plan and no ship nudge at the end of a run, even with `ship.enabled: true`. `bin/ultrathink-ship` still works when you run it yourself. |
| `ULTRATHINK_PSTACK=0` | The Cursor pstack hook injects nothing for this process, even with `pstack.enabled: true`. The exact string `0`. |
| `ULTRATHINK_PSTACK_CURSOR_DIR` | Absolute Cursor directory for the hook and for `ultrathink doctor`'s pstack section. Wins over `pstack.cursorDir`. |
| `ULTRATHINK_CONFIG_DIR` | When set, the Cursor hook reads only `<this directory>/config.json` for `pstack` and does not look at the usual user files. |
| `ULTRATHINK_DECISIONS=0` | No Jev decision at any point in this process, whatever the config says: no request to either rail, no decision record, no plan-skip notice and no `Decisions ·` summary segment. It is the only off switch: `bin/ultrathink status` shows `Decisions: off (ULTRATHINK_DECISIONS=0)`, and `bin/ultrathink decisions check` and `decisions probe` print `Decisions check: off (ULTRATHINK_DECISIONS=0)` or `Decisions probe: off (ULTRATHINK_DECISIONS=0)` and exit 1 without a request. |
| `ULTRATHINK_HOST` | Which host's state directory to use: `claude-code`, `grok-build`, `hermes`, `muse` or `omp`. Any other value is ignored. Without it the host is detected from its environment, and Claude Code is the fallback. Set it for `bin/ultrathink` to change another host's control state, for example `ULTRATHINK_HOST=omp bin/ultrathink off`. The Grok hook file, the Muse hook wrappers, the Hermes plugin and the Omp extension set it for their own processes. |
| `ULTRATHINK_STATE_DIR` | Use this directory instead of the host's state directory. Give an absolute path: a relative one is resolved against the session's working directory on Claude Code, Grok Build, Muse and Omp, but against the ultrathink checkout on Hermes. It is ignored when the path is inside a `.planning` directory. Teachable Moments state is `<this directory>/teach/`, never `<cwd>/.planning`. The Hermes plugin sets it for its own control commands. |
| `ULTRATHINK_HINDSIGHT=0` | No Hindsight request in this process, even with `hindsight.enabled: true`. The exact string `0`. `bin/ultrathink status` shows `Hindsight: off (ULTRATHINK_HINDSIGHT=0)`, and `bin/ultrathink hindsight check` exits 1 without a request. |
| `ULTRATHINK_RAGFLOW=0` | No RAGFlow request in this process, even with `ragflow.enabled: true`. Whitespace around `0` is trimmed. `bin/ultrathink status` shows `RAGFlow: off (ULTRATHINK_RAGFLOW=0)`, and `bin/ultrathink ragflow` exits 1 without a request. |
| `ULTRATHINK_TEACH=0` | Teachable Moments off for this process when `teach.enabled` is true: no capture, no recall, no promote. The exact string `0`. While `teach.enabled` is false the status line still says `Teach: off (opt-in: set teach.enabled)`. When enabled, it says `Teach: off (ULTRATHINK_TEACH=0)`. Mutating `teach` subcommands exit 1. |
| `HINDSIGHT_API_URL` | Hindsight base URL, used only when `hindsight.url` is empty. Same URL rules as `hindsight.url`. |
| `HINDSIGHT_API_KEY` | Hindsight API key, used when no `hindsight` key is stored. The stored key wins. The status line names this variable when the key is missing. |
| `HINDSIGHT_API_TOKEN` | Hindsight API key, used only when no `hindsight` key is stored and `HINDSIGHT_API_KEY` is empty. The ready status line then says `key from HINDSIGHT_API_TOKEN`. |
| `RAGFLOW_URL` | RAGFlow base URL, used only when `ragflow.url` is empty. Same URL rules as `ragflow.url`. |
| `RAGFLOW_API_KEY` | RAGFlow API key, used when no `ragflow` key is stored. The stored key wins. The status line names this variable when the key is missing. |
| `ULTRATHINK_MCP_STORE` | Path of the credential store. Default `~/.config/ultrathink/mcp-credentials.json` (under `$XDG_CONFIG_HOME` when set). |
| `ULTRATHINK_OAUTH_REDIRECT` | OAuth callback URL for `bin/ultrathink-mcp auth login`. Must be https, or http on `127.0.0.1`, `localhost` or `[::1]`. The `--redirect` flag wins over it. |
| `ULTRATHINK_OAUTH_TAILSCALE=1` | Same as `auth login --tailscale`: on a remote (SSH) session, receive the OAuth callback through `tailscale serve`. Without it, ultrathink never runs `tailscale`. Only the exact value `1` opts in. See [Commands](commands.md#binultrathink-mcp). |
| `ULTRATHINK_DEBUG=1` | The prompt hook (`hooks/uplift.ts`, used by Claude Code, Grok Build and Muse) writes `[ultrathink]` log lines to stderr. With Decisions on, every process that asks Jev (the prompt hook, the Hermes and Omp engine, `bin/ultrathink-ship`) also writes one `[ultrathink] decisions …` line per decision: the point, P or the error kind, the model, latency, attempts and cost. Never the message, the state or the key. |
| `ULTRATHINK_MCP_DEBUG=1` | `bin/ultrathink-mcp serve` writes relay log lines to stderr. |
| `ULTRATHINK_HERMES_TIMEOUT` | Hermes only. Longest time in seconds the Hermes plugin lets one plan run. A positive integer; anything else means the default, `540`. The plugin stops the plan at min(this, cap − 15) seconds, where the cap is Hermes' `plugins.hook_callback_timeout`, and does not start planning when that leaves less than 90 seconds. See the note below the table. |
| `ULTRATHINK_GATEWAY=0` | Force Hindsight, RAGFlow and the substrate brief back to their direct clients, even when a backend is `gateway`. |
| `DESK_GATEWAY_URL` | Desk gateway origin. Wins over `gateway.url`. |
| `DESK_GATEWAY_SEAT` | Seat path segment. Wins over `gateway.seat` when it matches `^[a-z][a-z0-9-]{0,31}$`. |
| `DESK_GATEWAY_TOKEN` | Seat bearer token, used when the credential store has no `desk-gateway` credential. Never printed. |
| `DESK_GATEWAY_TIMEOUT_MS` | Timeout for one gateway tool call, in milliseconds. An integer from 1 to 120000; otherwise `gateway.timeoutMs` is used. |
| `ULTRATHINK_HINDSIGHT_BACKEND` | `direct` or `gateway`. Wins over `hindsight.backend` unless `ULTRATHINK_GATEWAY=0`. |
| `ULTRATHINK_RAGFLOW_BACKEND` | `direct` or `gateway`. Wins over `ragflow.backend` unless `ULTRATHINK_GATEWAY=0`. |
| `ULTRATHINK_SUBSTRATE_BACKEND` | `direct` or `gateway`. Wins over `substrate.backend` unless `ULTRATHINK_GATEWAY=0`. |
| `SUBSTRATE_URL` | Agent Substrate base URL. Wins over `substrate.url`. |
| `SUBSTRATE_TOKEN` | Sent as `Authorization: Bearer <token>` on Agent Substrate requests. |
| `SUBSTRATE_TIMEOUT_MS` | Timeout for one Agent Substrate request, in milliseconds. A positive number; default `1500`. |
| `SUBSTRATE_DISABLED=1` | Never contact Agent Substrate, even when `SUBSTRATE_URL` or `substrate.url` is set. |
| `GSD_TOOLS` | Path of `gsd-tools.cjs`, which the ship assessment runs to read a GSD roadmap. See [GSD tools lookup](#gsd-tools-lookup). |
| `BUN` | Path of the `bun` binary. See [Finding Bun](#finding-bun). |
| `OPENROUTER_API_KEY` | OpenRouter API key for Jev decisions, used only when no `openrouter` key is stored with `bin/ultrathink-mcp auth set-key openrouter`. The stored key wins. Empty or whitespace-only counts as unset. `bin/ultrathink status` shows `key from OPENROUTER_API_KEY` when it is the one in use, never the key. |
| `AI_GATEWAY_API_KEY` | Vercel AI Gateway API key for Jev decisions, used only when no `vercel` key is stored with `bin/ultrathink-mcp auth set-key vercel`. The stored key wins. Empty or whitespace-only counts as unset. With `decisions.provider: "auto"` (the default), its presence picks the Vercel rail. `bin/ultrathink status` shows `key from AI_GATEWAY_API_KEY` when it is the one in use, never the key. |
| `ULTRATHINK_DECISIONS_URL` | Replaces the Decisions endpoint on the OpenRouter rail (`https://openrouter.ai/api/alpha/decisions`), for a local proxy or a test server. It is accepted only as an `https://` URL on `openrouter.ai`, or an `http://` or `https://` URL on `localhost`, `127.0.0.1` or `[::1]`, and never with a user name or password in it; any other value is ignored and the default endpoint is used. Only its origin and path are used and printed: a query or fragment is dropped. Environment only: there is no config key for it, so a project file cannot redirect your OpenRouter key. The Vercel rail ignores it (its endpoint is fixed) and never shows it. On the OpenRouter rail, when it is in effect, the `Decisions:` status line (when Decisions are on with a key) and the `decisions check` line end with ` · url <origin and path>`; when it is set but ignored, they end with ` · ULTRATHINK_DECISIONS_URL ignored (must be https://openrouter.ai/… or a loopback URL)`. |

About the Hermes hook cap: Hermes abandons a plugin hook that runs longer than its `plugins.hook_callback_timeout` (30 seconds unless you change it). A plan needs at least 90 seconds, so the cap must be at least 105 seconds; 600 is recommended. It is a global Hermes setting that affects every plugin, and nothing in ultrathink changes it. Set it yourself:

```sh
hermes config set plugins.hook_callback_timeout 600
```

The plugin asks Hermes for the cap it enforces. When that Hermes does not report it, the plugin reads `plugins.hook_callback_timeout` from the active Hermes profile's `config.yaml`, else assumes 30 seconds, and logs one warning naming the command above. That file is `$HERMES_HOME/config.yaml` (`~/.hermes/config.yaml` when `HERMES_HOME` is unset), or `<Hermes home>/profiles/<name>/config.yaml` when `active_profile` names a profile other than `default` or `HERMES_HOME` points at a profile directory.

#### GSD tools lookup

GSD (Get Shit Done) is a planning workflow that keeps a roadmap in `.planning/ROADMAP.md`. When a repository has one, `bin/ultrathink-ship assess` runs `gsd-tools.cjs` with `node` to read it, so Node.js must be on `PATH`. It looks for `gsd-tools.cjs` in this order, and the first match wins:

1. `$GSD_TOOLS`, when set.
2. `<repo>/gsd-core/bin/gsd-tools.cjs`, then `gsd-core/bin/gsd-tools.cjs` under `<repo>/.claude` and `<repo>/.codex`, then the legacy `<repo>/.claude/get-shit-done/bin/gsd-tools.cjs`.
3. `$CLAUDE_CONFIG_DIR/gsd-core/bin/gsd-tools.cjs`, when `CLAUDE_CONFIG_DIR` is set.
4. `gsd-core/bin/gsd-tools.cjs` under `~/.claude`, `~/.agents`, `$HERMES_HOME` (else `~/.hermes`), `$CODEX_HOME` (else `~/.codex`), `$GEMINI_CONFIG_DIR` (else `~/.gemini`), `~/.cursor` and `$XDG_CONFIG_HOME/opencode` (else `~/.config/opencode`), in that order.
5. The legacy `~/.claude/get-shit-done/bin/gsd-tools.cjs`.

A copy in the repository that git tracks is skipped, so code committed to a repository is never run. An untracked local install in the same place is still used.

When a roadmap exists and none of these is found, the assessment reports the gap `GSD roadmap found but gsd-tools.cjs was not found; set GSD_TOOLS or rerun assess with --ignore-gsd`. When the tools are found but `node` is not on `PATH`, it reports `GSD roadmap found but node is not on PATH, so gsd-tools.cjs could not run; install Node.js or rerun assess with --ignore-gsd`.

#### Finding Bun

The launcher `bin/run-bun` looks for `bun` in this order: `$BUN`, `PATH`, `$BUN_INSTALL/bin/bun`, `~/.bun/bin/bun`, `/usr/local/bin/bun`, `/opt/homebrew/bin/bun`, then `~/.local/share/*/bun/bin/bun`. It adds the directory it found to `PATH` for everything Bun starts, and starts Bun with `--no-env-file`, so Bun 1.3.3 and later load no `.env*` files from the working directory (your repository) into ultrathink; Bun 1.2.x ignores the flag and still loads them. When there is no Bun, it prints `ultrathink: bun not found. Install Bun 1.2 or later (https://bun.sh) or set BUN=/path/to/bun`; the hooks then exit 0 so the prompt still goes through, and the three CLIs exit 127. The Hermes plugin runs `$BUN` directly when it is set, else `bin/run-bun`, both from the ultrathink clone, so a repository's `.env*` files never reach it.

### Internal variables

ultrathink sets these itself. Do not set them.

| Variable | Purpose |
|---|---|
| `ULTRATHINK_CHILD` | Set to `1` on the headless `claude` calls the engine makes, so the hooks do not plan or track them. A process that has it set to `1` is never planned. |
| `ULTRATHINK_PROGRESS_FD` | File descriptor (3 or higher) that `hooks/engine.ts` writes planning progress to, one JSON line per event, when its caller sets it. Omp no longer uses it: the Omp extension plans in-process and reads progress directly. |
| `ULTRATHINK_BUN_REQUIRED` | Set to `1` by `bin/ultrathink`, `bin/ultrathink-mcp` and `bin/ultrathink-ship` so `bin/run-bun` exits 127 when Bun is missing. `bin/run-bun` removes it before starting Bun. |
| `MAX_THINKING_TOKENS` | Set to `0` on the headless `claude` calls when `claude.thinking` is `false`. |
| `GROK_SUBAGENTS`, `GROK_MEMORY`, `GROK_WEB_FETCH` | Set to `0` on the `grok` process the `cli` transport starts. `GROK_HOME` is set there too when `grok.home` is not empty. |

### Variables ultrathink reads from your system or host

| Variable | Used for |
|---|---|
| `HOME` | Default locations of the config files, the credential store and the host directories. |
| `XDG_CONFIG_HOME` | User config, credential store, the Muse state directory and Muse's `settings.json` for `mcp-register`. |
| `CLAUDE_CONFIG_DIR` | Claude user config, the Claude Code state directory, the `CLAUDE.md` that `scripts/setup.ts` edits, and the Claude config file `mcp-register` backs up. |
| `GROK_HOME` | Grok home: the `grok login` lookup when `grok.home` is empty, the Grok Build state directory when `GROK_PLUGIN_DATA` is unset, and where `scripts/setup.ts` installs the Grok rule and hook file. |
| `GROK_PLUGIN_DATA` | Grok Build state directory. |
| `HERMES_HOME` | Hermes state directory, Hermes' `config.yaml`, and the plugin path `scripts/setup.ts` prints. |
| `PI_CODING_AGENT_DIR` | Omp state directory and Omp's `mcp.json` for `mcp-register`. |
| `GROK_PLUGIN_ROOT`, `GROK_HOOK_EVENT`, `GROK_SESSION_ID` | Any of them set means the process runs under Grok Build. |
| `MUSE_TOOL_USE_ID`, `MUSE_PLUGIN_ID` | Either set means the process runs under Muse Code, so `bin/ultrathink` run from Muse's shell tool changes the Muse state. |
| `CLAUDE_PLUGIN_ROOT` | Set by the host for plugin hooks and commands. `hooks/hooks.json` and the command files in `commands/` use it to find the checkout. |
| `TERMINAL_CWD` | Hermes only: the working directory for planning when Hermes passes none, for every turn except local CLI (local CLI turns use the process directory first and this only as a fallback). |
| `HERMES_SESSION_USER_NAME`, `HERMES_SESSION_KEY` | Hermes gateway session values (read through Hermes' session context, not the process environment): the sender name whose `[Name] ` tag is stripped from shared-session messages, and the chat that `/ultrathink-quick` sends its message to. |
| `SSH_CONNECTION`, `SSH_CLIENT`, `SSH_TTY` | Any of them set marks a remote session, so `auth login` prints port-forwarding hints (and uses the Tailscale route when you opted in). |
| `USER`, `LOGNAME` | The user name in the printed `ssh -L` command. |
| `PATH`, `BUN_INSTALL` | Finding `bun`, and finding the `claude`, `grok` and `hermes` CLIs for `mcp-register`. |
| `CODEX_HOME`, `GEMINI_CONFIG_DIR` | Two of the [GSD tools](#gsd-tools-lookup) locations. |

## State directories

Each host keeps its own state. Planning never writes `.planning/` into the working directory.

| Host | State directory |
|---|---|
| Claude Code | `~/.claude/ultrathink` (`$CLAUDE_CONFIG_DIR/ultrathink` when set) |
| Grok Build | `$GROK_PLUGIN_DATA/ultrathink` when set, else `~/.grok/plugin-data/ultrathink` (`$GROK_HOME/plugin-data/ultrathink` when `GROK_HOME` is set) |
| Hermes Agent | `~/.hermes/ultrathink` (`$HERMES_HOME/ultrathink` when set) |
| Muse Code | `~/.config/muse/ultrathink` (`$XDG_CONFIG_HOME/muse/ultrathink` when set) |
| Omp | `~/.omp/agent/ultrathink` (`$PI_CODING_AGENT_DIR/ultrathink` when set) |
| Cursor | `~/.cursor/ultrathink` |

Empty or whitespace-only values count as unset. `ULTRATHINK_STATE_DIR` replaces the directory for every host, as long as it is not inside `.planning`. Use an absolute path for it: a relative path resolves against the session's working directory on most hosts, but against the ultrathink checkout on Hermes.

What a state directory holds:

| Path | Contents |
|---|---|
| `control.json` | The per-host control state, described in the next section. |
| `sessions/<session-id>.json` | The session record: the spec, the graph, the clarifications, the tracking plan, the created row links, the ship progress and, with Decisions on, the Jev decision records (`decisions`, and the ship assessment's `decision`). The kickoff, sync and ship skills take this file as `stateFile`. |
| `sessions/<session-id>.xml` | The full uplifted spec. |
| `last.json` | A copy of the latest session record. `bin/ultrathink last` reads it. |
| `last-plan.json` | The plan carrier for hosts that do not read hook output directly, such as Grok Build. |
| `.last-prune` | Empty marker written by the scheduled prune; its modification time is when the prune last ran. Only exists when `state.retentionDays` is set. |
| `teach/moments/<id>.json` | One Teachable Moments file. Written only when `teach.enabled` is on. |
| `teach/outbox/<id>.json` | A pending Hindsight retain, delete or tag update. |
| `teach/inbox/<id>.json` | A finished-turn digest waiting for `teach observe`. `teach observe --file` deletes the file afterwards, and only when the path resolved to a file under this directory. A refused path is left alone. |
| `teach/skill-drafts/<name>/SKILL.md` | A rendered skill draft. Hermes installs from here through `skill_manage`; ultrathink never writes `~/.hermes/skills`. |

## Control state versus config

There are two layers:

- **Config files** are shared by every host and are edited by hand (or by `notion init --write-config`).
- **Control state** is `control.json` in one host's state directory. The `/ultrathink-*` commands in an agent and `bin/ultrathink` on the command line write it. It only affects that host.

A value in the control state beats the config value until you change it again:

| Command | Control field | Overrides |
|---|---|---|
| `/ultrathink-off`, `/ultrathink-on`, `bin/ultrathink off`, `bin/ultrathink on` | `enabled` | `uplift.enabled` |
| `/ultrathink-skip` (Omp, and Claude Code via `${CLAUDE_SESSION_ID}`), `bin/ultrathink skip --session <id>`, `ctl skip --session <id>` (grok-bot) | per-session flag `sessions/<id>.skip` | Skips the next prompt of that session once, then clears itself. Not a `control.json` field. A skip with no session id is refused and arms nothing. |
| `/ultrathink-track off`, `/ultrathink-track on`, `bin/ultrathink track off`, `bin/ultrathink track on` | `trackEnabled` | `track.enabled`. `off` also stops the kickoff skill and `track complete` from creating rows. |
| `bin/ultrathink think on`, `bin/ultrathink think off` | `thinkEnabled` | `think.enabled` |
| `bin/ultrathink hitl on`, `bin/ultrathink hitl off` | `hitlEnabled` | `hitl.enabled` |
| `bin/ultrathink grok engine auto`, `… engine claude`, `… engine grok`, `… engine muse` | `engine` | `think.engine` (`auto` follows the config) |

`ULTRATHINK_TRACK=0` beats both the control state and the config, for the planner's own row creation. `ULTRATHINK_UPLIFT=0` and `ULTRATHINK_SHIP=0` likewise beat both for planning and ship.

`bin/ultrathink` picks the state directory from `ULTRATHINK_HOST`, else from the detected host: Grok Build when `GROK_PLUGIN_ROOT`, `GROK_HOOK_EVENT` or `GROK_SESSION_ID` is set, Muse when `MUSE_TOOL_USE_ID` or `MUSE_PLUGIN_ID` is set, and Claude Code otherwise. Run from a plain shell, it changes the Claude Code state. See [Commands](commands.md) for every command and how each host shows the reply.

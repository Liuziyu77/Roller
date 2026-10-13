# CLI reference

Use this page to look up Roller command-line flags. If this is your first run, complete [Getting started](getting-started.md) first. Return here when you need to change tasks, concurrency, output paths, or Harness behavior.

For a first pass, remember four things:

- `--tasks` selects what Roller will run.
- `--model` and `--harness` select the model and Agent runtime.
- `--output` and `--run-name` decide where results are saved.
- `--dry-run` checks the configuration without starting containers.

The command output from the Roller version currently in use is always authoritative:

```bash
roller --help
roller collect --help
roller view --help
```

## 1. Command structure

Choose the command for the job first, then add that command's flags.

| Command | Purpose |
| --- | --- |
| `roller collect [OPTIONS]` | Reads tasks, runs a Harness, and collects trajectories |
| `roller view RUN_DIR` | Opens an existing run in the Viewer |
| `roller bench ...` | Lists, exports, or summarizes benchmarks, with collection flags in section 8 |
| `roller --version` | Shows the installed Roller version |

The smallest collect command needs a task list. Set the model with `--model` or in each task's `model` field.

```bash
roller collect --tasks tasks.jsonl --model provider/model
```

## 2. Configuration precedence

The same setting can appear in both a task and the command line. Roller uses the following rules to choose the final value.

| Setting | Final value |
| --- | --- |
| Model | Command-line `--model` values win when present, otherwise use each task's `model` |
| Thinking | task `runtime.thinking` wins, followed by `--thinking`, then the Harness or model default |
| Workspace | task `workspace` wins, otherwise use the global `--workspace` |
| User Simulator model | `user_simulator.model` wins, otherwise follow the current task Agent model |

Roller removes duplicate `--model` values. When you specify multiple models, every selected task runs once for each model. `--start-index` and `--limit` select tasks before Roller expands those model combinations.

## 3. Shared collection flags

These flags decide which tasks to run, how many runs to create, and where to save the results. They work with every Harness.

### Inputs and runtime selection

These flags tell Roller where to read tasks and which model and Harness should execute them.

| Flag | Default | Purpose |
| --- | --- | --- |
| `--tasks PATH` | Required | Selects a JSON or JSONL task list |
| `--model MODEL` | task `model` | Selects a model and can be repeated for multiple models |
| `--model-label LABEL` | Actual service model ID | Sets a safe local name for sample directories and containers without changing the upstream model ID, only for runs with one final model |
| `--harness NAME` | task `harness` or `openclaw` | Selects `openclaw`, `codex`, `claude-code`, `hermes`, `opencode`, `deepseek`, or `pi` |

### Execution scale and task range

These flags control concurrency, repetitions, retries, and which part of the task list runs.

| Flag | Default | Purpose |
| --- | --- | --- |
| `--parallel N` | `1` | Sets the maximum number of concurrent rollouts |
| `--grader-parallel N` | `--parallel` | Limits concurrent graders separately to avoid overloading a judge service |
| `--samples N` | `3` for SkillsBench, otherwise `1` | Creates N independent samples for each task/model pair |
| `--retries N` | `0` | Sets additional attempts after the first failure |
| `--timeout SECONDS` | `600` | Sets the total timeout for one rollout |
| `--task-timeouts` | Off | Prefers each task's `timeout_seconds` and falls back to `--timeout` |
| `--start-index N` | `0` | Starts at task N in the normalized task list |
| `--limit N` | Unlimited | Selects at most N tasks |

### Output, validation, and continuation

These flags control the result directory and whether Roller validates, starts, or continues a run.

| Flag | Default | Purpose |
| --- | --- | --- |
| `--output DIR` | `runs` | Sets the parent directory for all run roots |
| `--run-name NAME` | UTC timestamp | Sets the directory name for this run |
| `--dry-run` | Off | Checks tasks, files, and the run plan without starting Docker |
| `--resume` | Off | Continues the same run and skips complete successful samples, see section 6 |

### Compatibility and debugging

These flags mainly support legacy data or logging. New task files usually do not need the first three.

| Flag | Default | Purpose |
| --- | --- | --- |
| `--workspace DIR` | None | Sets a global workspace for legacy tasks, new tasks use `file_root` and `files` |
| `--prompt-key NAME` | `prompt` | Selects the prompt field in legacy data |
| `--id-key NAME` | `id` | Selects the ID field in legacy data |
| `--log-level LEVEL` | `INFO` | Sets `DEBUG`, `INFO`, `WARNING`, or `ERROR` logging |

### Input file limits

These flags limit the files that one task can bring into a container and help prevent unexpectedly large inputs.

| Flag | Default | Purpose |
| --- | --- | --- |
| `--max-input-file-bytes` | 10 GiB | Limits one input or context file |
| `--max-task-input-bytes` | 50 GiB | Limits the total input size for one task |

## 4. Common Harness runtime flags

These flags control how a Harness container starts, connects to a model service, and records trajectory data. The selected Harness still determines the supported values.

### Container and connection

These flags select the image, Docker runtime settings, and model-service connection.

| Flag | Default | Purpose |
| --- | --- | --- |
| `--docker-image IMAGE` | Pinned image for the Harness | Overrides the Harness image for this run |
| `--container-user USER` | `0` | Sets the disposable container user, `image` keeps the image default |
| `--docker-binary PATH` | `docker` | Selects the Docker CLI name or path |
| `--network MODE` | `host` | Sets the container network mode, some full wire-trace paths require host networking |
| `--api-base URL` | Harness environment variable | Sets the API address for a single-Harness run, OpenClaw keeps this in its model config |
| `--api-key-env NAME` | Harness default variable | Selects the host environment variable that contains the model API key |
| `--pass-env NAME` | None | Passes one additional non-empty environment variable into the Harness container and can be repeated |
| `--keep-container-on-error` | Off | Keeps the stopped container after failure for inspection |

### Reasoning and traces

`--thinking` sets the model's reasoning or thinking effort. The same setting can appear in a task as `runtime.thinking`. The task value takes precedence over the CLI. If both are omitted, Roller uses the Harness or model default.

The Roller CLI recognizes the logical levels below, but each Harness supports only a subset and may use different defaults or mappings. See the matching Harness guide for the exact behavior.

| Flag | Default | Purpose |
| --- | --- | --- |
| `--thinking LEVEL` | Unset | Sets the Harness reasoning or thinking level |
| `--thinking-capabilities PATH` | Unset | Loads versioned model/endpoint capability declarations for preflight validation |
| `--keep-thinking` / `--no-keep-thinking` | On | Decides whether ACTF and SFT export visible reasoning |
| `--wire-trace MODE` | `actf` | Selects `off`, `actf`, or `full` request recording |

```text
off | minimal | low | medium | high | xhigh | adaptive | max | ultra
```

Input `none` is normalized to `off`. Unsupported values fail before the rollout starts.

For all seven Harnesses, provider/model support can be declared
without adding model-name rules to Roller:

```json
{
  "schema_version": "roller.thinking-capabilities/v1",
  "profiles": [
    {
      "harness": "hermes",
      "model": "served-model-id",
      "api_base": "https://gateway.example/v1",
      "supported_efforts": ["low", "medium", "high"]
    }
  ]
}
```

Pass this file with `--thinking-capabilities`. Matching is exact on Harness and
served model ID; `api_base` is optional, and an endpoint-specific entry takes
precedence over a generic entry. A matched unsupported effort fails before any
container or model request starts. Unmatched models retain provider-side
validation, and Roller never silently substitutes another effort. The file's
SHA-256 is included in the run lock.

Profiles support all seven registered harnesses and validate both agent and
simulator. Unknown harnesses/fields and surrounding whitespace are rejected.
Use logical Roller effort names (Claude `ultra`, not its wire value `ultracode`).
OpenClaw matches the full `provider/model` name and resolves the endpoint from
that provider's model-config `baseUrl`. If the endpoint is unavailable, only
generic profiles match. Declarations never override native effort restrictions
or rewrite requests.

### Wire trace modes

Wire trace controls whether Roller records the actual HTTP requests sent to the model service. The default `actf` mode is sufficient for normal collection.

| Mode | Output and purpose |
| --- | --- |
| `off` | Does not capture HTTP requests through the local reverse proxy |
| `actf` | Writes the actual tools schema into ACTF and keeps no extra wire file |
| `full` | Also keeps `wire_trace.jsonl` for auditing actual HTTP requests |

`full` can retain complete request text including prompts, reasoning, tool arguments, and results. This makes the output larger and more sensitive. See the matching Harness guide for support and network requirements, and see {ref}`Trajectory outputs <wire-trace-jsonl>` for the file format.

### Compatibility note

`--external-thinking` has been removed. Replace it with `--thinking` and delete obsolete arguments from old commands.

## 5. Harness-specific flag index

When a flag belongs to one Harness, look it up in that Harness guide. Each guide owns its image, API, key, execution limit, and native configuration flags.

| Harness | Flag and configuration guide |
| --- | --- |
| OpenClaw | {ref}`OpenClaw Harness guide <openclaw-cli-flags>` |
| Codex | {ref}`Codex Harness guide <codex-cli-flags>` |
| Claude Code | {ref}`Claude Code Harness guide <claude-code-cli-flags>` |
| Hermes | {ref}`Hermes Harness guide <hermes-cli-flags>` |
| OpenCode | {ref}`OpenCode Harness guide <opencode-cli-flags>` |
| DeepSeek | {ref}`DeepSeek Harness guide <deepseek-cli-flags>` |
| Pi Agent | {ref}`Pi Agent Harness guide <pi-cli-flags>` |

To inspect the complete flag set supported by the Roller version currently in use, run:

```bash
roller collect --help
```

## 6. Resume flags

Use `--resume` to continue the same run after interruption or partial failure while reusing complete successful samples.

```bash
roller collect [original command] --resume
```

Resume first compares the execution settings and input digests in `lock.json`, then checks the required artifacts of successful samples. A sample is skipped when its settings and inputs match and its artifacts are complete. Damaged artifacts are rerun. Changed settings or inputs cause Resume to stop.

Use `--resume` only for the same experiment. Start a new `--run-name` after changing the model, image, thinking, wire, or any other setting that affects execution.

## 7. Viewer flags

Viewer flags select the run to open and configure the local web server's listen address and port.

```bash
roller view RUN_DIR [--host HOST] [--port PORT]
```

| Flag | Default | Purpose |
| --- | --- | --- |
| `RUN_DIR` | Required | Selects a Roller run containing `info.json` and `samples/` |
| `--host` | `127.0.0.1` | Sets the listen address |
| `--port` | `8765` | Sets the listen port |

Listening on `0.0.0.0` exposes trajectory contents to the network. For remote access, keep the default address and use SSH port forwarding.

## 8. Bench flags

Bench flags convert an external benchmark into Roller tasks, run collection, grade the results, and produce a summary.

| Command | Purpose |
| --- | --- |
| `roller bench list` | Lists the available benchmark adapters |
| `roller collect --bench ...` | Converts, runs, grades, and summarizes a benchmark, recommended for most users |
| `roller bench export ...` | Converts a benchmark to task JSONL without running tasks |
| `roller bench report RUN_DIR` | Regenerates a grading summary for an existing run |

Common command forms:

```bash
roller collect --bench NAME --bench-root ROOT [--bench-category CAT]... [--bench-task-id ID]... [--bench-variant NAME] [--bench-timeout-multiplier N] ...
roller bench export NAME ROOT --output TASKS.jsonl [--category CAT]... [--task-id ID]... [--variant NAME] [--timeout-multiplier N]
roller bench report RUN_DIR [--output REPORT.json]
```

Prefer `collect --bench`. It converts tasks, runs containers, grades results, and aggregates them in one command, then saves `tasks.jsonl` and `bench-report.json` in the run directory.

| Flag | Default | Purpose |
| --- | --- | --- |
| `--bench NAME` / `NAME` | Required | Selects an adapter from `roller bench list` |
| `--bench-root ROOT` / `ROOT` | Required | Selects the checked-out benchmark directory |
| `--bench-category CAT` / `--category CAT` | Unlimited | Selects one category and can be repeated |
| `--bench-task-id ID` / `--task-id ID` | Unlimited | Selects one task and can be repeated, invalid IDs fail immediately |
| `--bench-variant NAME` / `--variant NAME` | Adapter default | Selects a benchmark condition such as SkillsBench `with-skill` or `no-skill` |
| `--bench-timeout-multiplier N` / `--timeout-multiplier N` | Adapter default | Scales each benchmark task timeout by a finite positive number |
| `--output` / `-o` | Required for export | Sets the exported task JSONL or report JSON |
| `RUN_DIR` | Required for report | Selects a completed run and is a positional argument |
| `--rebuild-task-images` | Off | Rebuilds task-specific benchmark images even when they already exist |

`collect --bench` automatically uses each benchmark task's timeout. For a manual export followed by collect, add `--task-timeouts` to collect. Both workflows can use `--pass-env` for environment variables required by the grader.

See [Bench integration and scoring](../benches/bench-format.md) for field semantics, scoring order, `stage` leak prevention, and aggregation rules.

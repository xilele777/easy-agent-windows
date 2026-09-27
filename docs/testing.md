# Testing

## Production gate

Run the same offline gate used by pull requests:

```bash
npm ci
npm run verify:production
```

The command runs TypeScript validation, builds the distributable CLI, and executes the `core`, `extensions`, and `ui` test groups. Any failed test or timeout returns a non-zero exit code. CI runs this default offline gate on Windows for code changes on feature branches. Pushes to `main` and manual CI runs also run it on Linux and macOS, plus their host sandbox checks. Documentation-only push and pull request changes skip CI; mixed changes still run it. `npm run verify:release` includes this gate before the package and installation checks.

Each offline test process receives a temporary `HOME`, `USERPROFILE`, XDG directories, and Windows application-data directories. Provider credentials, API endpoints, MCP settings, editor overrides, and `EASY_AGENT_*` feature settings inherited from the developer environment are removed. Tests must create their own configuration and fixtures under the assigned temporary directories.

## Coverage inventory

| Area | Included checks | Execution |
| --- | --- | --- |
| Core flow | CLI and Headless protocols, QueryEngine commands, provider stream adapters, tools, ToolSearch, MCP, Skills, tasks, and agents | `core` |
| Permissions | Allow/deny behavior, structured Bash read-only analysis, realpath and symbolic-link boundaries, Auto Mode configuration, Plan Mode paths, and sandbox policy | `core` |
| Storage and configuration | Configuration precedence and source shapes, workspace trust, credential inheritance, headless routing, session JSONL and restore shape, file history, and retention | `core`, `extensions` |
| Extensions | Worktrees, agent teams, hooks, commands, web and multimodal tools, plugins, and resilience | `extensions` |
| UI | Ink rendering, input, transcript, permission prompts, progress, status line, and plugin management | `ui` |
| Release | Package metadata, bundle, tarball contents, isolated installation, installer behavior, and old Node failure path | `verify:release` |
| Platform | Host sandbox and Bash sandbox integration | `platform` |
| External | Real provider streaming, ToolSearch, Auto Mode classifier requests, and plugin compatibility against a supplied package | `live`, `verify:plugin` |

The checked-in characterization fixtures are:

- `cli-headless-characterization.golden.txt` for CLI flags, stdin merging, and text, JSON, and stream JSON output.
- `queryengine-characterization.golden.txt` for local commands and orchestration events.
- `providerstream-characterization.golden.txt` for provider request translation and stream events.
- `config-session-characterization.golden.txt` for configuration precedence, session JSONL, and restored session data.

## Execution groups

| Group | Command | Default gate |
| --- | --- | --- |
| `core` | `npm run verify:production:core` | Yes |
| `extensions` | `npm run verify:production:extensions` | Yes |
| `ui` | `npm run verify:production:ui` | Yes |
| `platform` | `npm run verify:production:platform` | macOS and Linux CI |
| `live` | `npm run verify:production:live` | No |

List every test selected by a group without running it:

```bash
node --import tsx scripts/verify-production.ts --group core --list
```

Multiple `--group` options may be combined. Tests in the default gate run sequentially with independent user directories so failures are reproducible and shared process state cannot leak between test files.

Run the Bash read-only security regression suite directly while changing command parsing or permission behavior:

```bash
npm run test:bash-readonly
```

Run the workspace path boundary suite after changing file tools, allowed roots, file history, or path handling:

```bash
npm run test:path-boundary
```

Run the Grep command selection regression after changing its executable fallback:

```bash
npm run test:grep-command
```

Run the offline workflow regression after changing the agent loop, permissions, diff, or file history:

```bash
npm run test:workflow-offline
```

Run the persistence suite after changing settings, runtime state, tasks, teams, sessions, or atomic file writes:

```bash
npm run test:persistence
```

Run the subprocess suite after changing Bash, PowerShell, hooks, the status line, or process cleanup:

```bash
npm run test:controlled-process
```

The Stage 22 hook suite uses POSIX shell syntax and runs in the production gate on macOS and Linux. The Windows gate runs `npm run test:windows-shell` for native PowerShell hooks, the PowerShell tool and cancellation, `apiKeyHelper`, and missing shell diagnostics.

The Bash streaming smoke uses a POSIX `for` loop and runs on macOS and Linux. Windows uses the PowerShell tool for native commands; this smoke does not claim to test PowerShell streaming.

Run the configuration trust suite after changing settings precedence, environment loading, providers, MCP, plugins, sandbox settings, or headless startup:

```bash
npm run test:config-trust
```

## Platform and external checks

Platform tests exercise the actual host sandbox and therefore run separately from the portable offline gate:

```bash
npm run verify:production:platform
```

Linux host tests require `bubblewrap`, `socat`, `rg`, and permission to create unprivileged user, PID, and network namespaces. The suite verifies real read/write restrictions, allowed and denied network destinations, fail-closed configuration errors, output, and exit-code preservation.

Live tests require valid provider credentials and may consume API quota. They run only when requested explicitly:

```bash
npm run verify:production:live
```

For the six-task Windows real-model benchmark, build the CLI and configure a user-level model profile. Check the six initial failing fixtures without a provider call, then run three repetitions per task:

```powershell
node --import tsx scripts/benchmark-windows.ts --check-fixtures
node --import tsx scripts/benchmark-windows.ts --output "$env:TEMP\easy-agent-benchmark.jsonl"
```

The script defaults to the `deepseek` profile; set `EASY_AGENT_BENCHMARK_PROFILE` to use another configured profile. It creates a fresh temporary Git repository for each of the 18 runs. Each JSONL record includes the baseline commit and fixture hash, profile, CLI and test status, changed-file list, Git diff, wall time, model-reported time, Token counts, and failure category. It removes the temporary repositories on exit. The optional `--output` file is replaced at the start of a run. Keep that file private until reviewed because it contains model-edited code and test diagnostics; API keys and raw provider replies are excluded or redacted. This credentialed live check is outside the default gate.

For an isolated diagnostic run, pass `--task retry-boundary --repeats 1`; omit these options for the full 18-run benchmark. A failed provider setup is recorded as an environment failure, and the structured result or CLI error is saved in redacted form.

The benchmark needs the credential variable referenced by the selected model profile. The local `deepseek` profile used for the 2026-09-27 run references `OPENAI_API_KEY`, which holds a DeepSeek key for that endpoint; it does not require an Anthropic key. If a Windows user variable is saved but the current PowerShell process has not inherited it, import it for this process before running the benchmark:

```powershell
$env:OPENAI_API_KEY = (Get-ItemProperty 'HKCU:\Environment').OPENAI_API_KEY
```

Use the variable name from your own profile. Do not print its value or write it to benchmark results.

Plugin compatibility verification also requires an explicit package path or repository URL and remains outside the default gate:

```bash
npm run verify:plugin -- /path/to/plugin
```

## Adding coverage

Add deterministic tests to the appropriate group in `scripts/verify-production.ts`. A test included in the offline gate must not read the real user profile, load the repository `.env`, call a public endpoint, require an interactive terminal, or mutate host state. Put host-dependent checks in `platform` and credentialed network checks in `live`.

## Agent Teams lifecycle

Run `npm run test:team-lifecycle` to check concurrent team writes, shared task ownership, control messages and crash recovery. This test is included in `npm run verify:production`.

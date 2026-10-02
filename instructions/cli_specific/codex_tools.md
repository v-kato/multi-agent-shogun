# Codex CLI Tools

This section describes OpenAI Codex CLI-specific tools and features.

## Tool Usage

Codex CLI provides tools for file operations, code execution, and system interaction within a sandboxed environment:

- **File Read/Write**: Read and edit files within the working directory (controlled by sandbox mode)
- **Shell Commands**: Execute terminal commands with approval policies controlling when user consent is required
- **Web Search**: Integrated web search via `--search` flag (cached by default, live mode available)
- **Code Review**: Built-in `/review` command reads diff and reports prioritized findings without modifying files
- **Image Input**: Attach images via `-i`/`--image` flag or paste into composer for multimodal analysis
- **MCP Tools**: Extensible via Model Context Protocol servers configured in `~/.codex/config.toml`

## Tool Guidelines

1. **Sandbox-aware operations**: All file/command operations are constrained by the active sandbox mode
2. **Approval policy compliance**: Respect the configured `--ask-for-approval` setting — never bypass unless explicitly configured
3. **AGENTS.md auto-load**: Instructions are loaded automatically from Git root to CWD; no manual cache clearing needed
4. **Non-interactive mode**: Use `codex exec` for headless automation with JSONL output

## Permission Model

Codex uses a two-axis security model: **sandbox mode** (technical capabilities) + **approval policy** (when to pause).

### Sandbox Modes (`--sandbox` / `-s`)

| Mode | File Access | Commands | Network |
|------|------------|----------|---------|
| `read-only` | Read only | Blocked | Blocked |
| `workspace-write` | Read/write in CWD + /tmp | Allowed in workspace | Blocked by default |
| `danger-full-access` | Unrestricted | Unrestricted | Allowed |

### Approval Policies (`--ask-for-approval` / `-a`)

| Policy | Behavior |
|--------|----------|
| `untrusted` | Auto-executes workspace operations; asks for untrusted commands |
| `on-failure` | Asks only when errors occur |
| `on-request` | Pauses before actions outside workspace, network access, untrusted commands |
| `never` | No approval prompts (respects sandbox constraints) |

### Shortcut Flags

- `--full-auto`: Sets `--ask-for-approval on-request` + `--sandbox workspace-write` (recommended for unattended work)
- `--dangerously-bypass-approvals-and-sandbox` / `--yolo`: Bypasses all approvals and sandboxing (unsafe, VM-only)

**Shogun system usage**: Ashigaru run with `--full-auto` or `--yolo` depending on settings.yaml `cli.options.codex.approval_policy`.

## Memory / State Management

### AGENTS.md (Codex's instruction file)

Codex reads `AGENTS.md` files automatically before doing any work. Discovery order:

1. **Global**: `~/.codex/AGENTS.md` or `~/.codex/AGENTS.override.md`
2. **Project**: Walking from Git root to CWD, checking each directory for `AGENTS.override.md` then `AGENTS.md`

Files are merged root-downward (closer directories override earlier guidance).

**Key constraints**:
- Combined size cap: `project_doc_max_bytes` (default 32 KiB, configurable in `config.toml`)
- Empty files are skipped; only one file per directory is included
- `AGENTS.override.md` temporarily replaces `AGENTS.md` at the same level

**Customization** (`~/.codex/config.toml`):
```toml
project_doc_fallback_filenames = ["TEAM_GUIDE.md", ".agents.md"]
project_doc_max_bytes = 65536
```

Set `CODEX_HOME` env var for project-specific automation profiles.

### Session Persistence

Sessions are stored locally. Use `/resume` or `codex exec resume` to continue previous conversations.

### No Memory MCP equivalent

Codex does not have a built-in persistent memory system like Claude Code's Memory MCP. For cross-session knowledge, rely on:
- AGENTS.md (project-level instructions)
- File-based state (queue/tasks/*.yaml, queue/reports/*.yaml)
- MCP servers if configured

## Codex-Specific Commands (Slash Commands)

### Session Management

| Command | Purpose | Claude Code equivalent |
|---------|---------|----------------------|
| `/new` | Start fresh conversation within current session | `/clear` (closest) |
| `/resume` | Resume a saved conversation | `claude --continue` |
| `/fork` | Fork current conversation into new thread | No equivalent |
| `/quit` / `/exit` | Terminate session | Ctrl-C |
| `/compact` | Summarize conversation to free tokens | Auto-compaction |

### Configuration

| Command | Purpose | Claude Code equivalent |
|---------|---------|----------------------|
| `/model` | Choose active model (+ reasoning effort) | `/model` |
| `/personality` | Choose communication style | No equivalent |
| `/permissions` | Set approval/sandbox levels | No equivalent (set at launch) |
| `/status` | Display session config and token usage | No equivalent |

### Workspace Tools

| Command | Purpose | Claude Code equivalent |
|---------|---------|----------------------|
| `/diff` | Show Git diff including untracked files | `git diff` via Bash |
| `/review` | Analyze working tree for issues | Manual review via tools |
| `/mention` | Attach a file to conversation | `@` fuzzy search |
| `/ps` | Show background terminals and output | No equivalent |
| `/mcp` | List configured MCP tools | No equivalent |
| `/apps` | Browse connectors/apps | No equivalent |
| `/init` | Generate AGENTS.md scaffold | No equivalent |

**Key difference from Claude Code**: Codex uses `/new` instead of `/clear` for context reset. `/new` starts a fresh conversation but the session remains active. `/compact` explicitly triggers conversation summarization (Claude Code does this automatically).

## Compaction Recovery

Codex handles compaction differently from Claude Code:

1. **Automatic**: Codex auto-compacts when approaching context limits (similar to Claude Code)
2. **Manual**: Use `/compact` to explicitly trigger summarization
3. **Recovery procedure**: After compaction or `/new`, the AGENTS.md is automatically re-read

### Shogun System Recovery (Codex Ashigaru)

```
Step 1: AGENTS.md is auto-loaded (contains recovery procedure)
Step 2: Read queue/tasks/ashigaru{N}.yaml → determine current task
Step 3: If task has "target_path:" → read that file
Step 4: Resume work based on task status
```

**Note**: Unlike Claude Code, Codex has no `mcp__memory__read_graph` equivalent. Recovery relies entirely on AGENTS.md + YAML files.

## tmux Interaction

### TUI Mode (default `codex`)

- Codex runs a fullscreen TUI using alt-screen
- `--no-alt-screen` flag disables alternate screen mode (critical for tmux integration)
- With `--no-alt-screen`, send-keys and capture-pane should work similarly to Claude Code
- Prompt detection: TUI prompt format differs from Claude Code's `❯` — pattern TBD after testing

### Non-Interactive Mode (`codex exec`)

- Runs headless, outputs to stdout (text or JSONL with `--json`)
- No alt-screen issues — ideal for tmux pane integration
- `codex exec --full-auto --json "task description"` for automated execution
- Can resume sessions: `codex exec resume`
- Output file support: `--output-last-message, -o` writes final message to file

### send-keys Compatibility

下表は人手で `tmux send-keys` を使って操作する場合の相性を示す参考である
(自動nudgeの可否とは別の話——自動nudgeについては次項「Nudge Mechanism」)。

| Mode | send-keys (人手) | capture-pane | Notes |
|------|-----------------|-------------|-------|
| TUI (default) | Risky (alt-screen) | Risky | Use `--no-alt-screen` |
| TUI + `--no-alt-screen` | Should work | Should work | Preferred for tmux |
| `codex exec` | N/A (non-interactive) | stdout capture | Best for automation |

### Nudge Mechanism (自動打鍵は有効)

2026-09-08、nudge の Enter が確認モーダルの既定選択肢を選び、D002-E1 違反の
削除が実行された。「削除するな」という命令を届けたことが、削除する釦を
押した。以後4世代にわたり「画面から安全を証明する」試みを重ねたが4度とも
破れ、将軍は一時★自動打鍵の安全集合を空とする裁定を下した。しかし
2026-09-10、cmd_760により復元され、nudgeは現在も有効である(詳細は
`instructions/common/protocol.md`の「Delivery Mechanism」節)。

For TUI mode:
- ★inbox_watcher は nudge(`tmux send-keys`による`inboxN`打鍵)を★実際に
  送信する。Codexのsuggestion UIを解除する専用処理(`x`→C-u)を挟む。
- ★Codex には Stop hook が無く、agent 自前の self-watch も実在しない。
  すなわちCodex agentへの★確定配送経路(送信を裏付ける仕組み)は存在せず、
  nudgeはベストエフォートに留まる。
- watcherは0〜2分は通常nudge、2〜4分もEscapeエスカレーションは無効化
  され通常nudgeへフォールバックする(Codex CLIはESCが「中断」になり
  やすいため)。4分を過ぎても★`/clear`(`/new`)エスカレーションはCodex
  には送られない——会話が切れてしまうため実装は安全側に倒し、通常
  nudgeへ留めたままタイマーをリセットする(`scripts/inbox_watcher.sh`
  のPhase3 codex分岐)。閾値超過で家老inboxへ自動で上がる機構もいずれの
  段階にも無い。確定配送経路が無い以上、届いたか疑わしいときに気づいて
  動くのは★人である。
- `type: clear_command`メッセージ(Redo Protocol等)受信時は、上記の
  時間エスカレーションとは別に即座に`/new`へ変換されて★自動送信される
  (busy中は次サイクルへ延期)。
- ★対象paneに確認モーダルが表示されている間は、そのagent宛てに
  `inbox_write`しないこと(「Delivery Mechanism」節と同趣旨)。
- 詳細: `docs/delivery_channels.md`

For `codex exec` mode:
- Each task is a separate `codex exec` invocation
- 元より nudge を要さぬ経路である(task 内容を引数で渡す)。

## MCP Configuration

Codex configures MCP servers in `~/.codex/config.toml`:

```toml
[mcp_servers.memory]
type = "stdio"
command = "npx"
args = ["-y", "@anthropic/memory-mcp"]

[mcp_servers.github]
type = "stdio"
command = "npx"
args = ["-y", "@anthropic/github-mcp"]
```

### Key differences from Claude Code MCP:

| Aspect | Claude Code | Codex CLI |
|--------|------------|-----------|
| Config format | JSON (`.mcp.json`) | TOML (`config.toml`) |
| Server types | stdio, SSE | stdio, Streamable HTTP |
| OAuth support | No | Yes (`codex mcp login`) |
| Tool filtering | No | `enabled_tools` / `disabled_tools` |
| Timeout config | No | `startup_timeout_sec`, `tool_timeout_sec` |
| Add command | `claude mcp add` | `codex mcp add` |

## Model Selection

### Command Line

```bash
codex --model codex-mini-latest      # Lightweight model
codex --model gpt-5.3-codex          # Full model (subscription)
codex --model o4-mini                # Reasoning model
```

### In-Session

Use `/model` to switch models during a session (includes reasoning effort setting when available).

### Shogun System

Model is set by `build_cli_command()` in cli_adapter.sh based on settings.yaml. Karo cannot dynamically switch Codex models via inbox (no `/model` send-keys equivalent in exec mode).

## Limitations (vs Claude Code)

| Feature | Claude Code | Codex CLI | Impact |
|---------|------------|-----------|--------|
| Memory MCP | Built-in | Not built-in (configurable) | Recovery relies on AGENTS.md + files |
| Task tool (subagents) | Yes | No | Cannot spawn sub-agents |
| Skill system | Yes | No | No slash command skills |
| Dynamic model switch | inbox `model_switch`で`/model`を★自動送信 | `/model` in TUI only(自動送信非対応) | Codexのみ人手が要る |
| `/clear` context reset | Yes | `/new` (TUI only) | Exec mode: new invocation |
| Prompt caching | 90% discount | 75% discount | Higher cost per token |
| Subscription limits | API-based (no limit) | msg/5h limits (Plus/Pro) | Bottleneck for parallel ops |
| Alt-screen | No (terminal-native) | Yes (TUI, unless `--no-alt-screen`) | tmux integration risk |
| Sandbox | None built-in | OS-level (landlock/seatbelt) | Safer automated execution |
| Structured output | Text only | JSONL (`--json`) | Better for parsing |
| Local/OSS models | No | Yes (`--oss` via Ollama) | Offline/cost-free option |

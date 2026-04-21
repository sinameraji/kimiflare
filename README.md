# kimiflare

A terminal coding agent powered by **[Kimi-K2.6](https://developers.cloudflare.com/workers-ai/models/kimi-k2.6/)** on Cloudflare Workers AI. It's Claude Code, but the model is Moonshot's 1T-parameter open-source Kimi running directly on your Cloudflare account — no middleman, no AI Gateway, no OpenAI SDK. You bring the token, your traffic goes straight to Cloudflare.

```
$ kimiflare
kimiflare · /help for commands · ctrl-c to exit

› what files are here?
  ✓ glob(*)
    /Users/you/proj/package.json
    /Users/you/proj/src/index.ts
    ...

› add a /health endpoint to server.ts
  ✓ read(src/server.ts)
  ◐ edit src/server.ts
    ─── permission requested ──────────────────
    @@ -42,6 +42,10 @@
       app.get('/', …)
    +  app.get('/health', (_, res) => res.json({ ok: true }))
    ─────────────────────────────────────────────
    [Allow once] [Allow for session] [Deny]
```

## Install

```sh
npm install -g kimiflare
```

Or run without installing:

```sh
npx kimiflare
```

Requires Node.js ≥ 20.

## Configure

Get credentials from Cloudflare:

1. https://dash.cloudflare.com → your account → copy **Account ID**.
2. https://dash.cloudflare.com/profile/api-tokens → **Create Token** → Custom token with **Account › Workers AI › Read** on your account → **Create** → copy.

Then either export them each shell:

```sh
export CLOUDFLARE_ACCOUNT_ID=...
export CLOUDFLARE_API_TOKEN=...
```

or save them once (`chmod 600` automatically):

```sh
mkdir -p ~/.config/kimiflare
cat > ~/.config/kimiflare/config.json <<'EOF'
{
  "accountId": "YOUR_ACCOUNT_ID",
  "apiToken":  "YOUR_API_TOKEN",
  "model":     "@cf/moonshotai/kimi-k2.6"
}
EOF
chmod 600 ~/.config/kimiflare/config.json
```

## Usage

```sh
kimiflare                             # interactive TUI
kimiflare -p "summarize PLAN.md"      # one-shot, streams answer to stdout
kimiflare -p "..." --dangerously-allow-all   # auto-approve mutating tools (for scripts)
kimiflare --model @cf/moonshotai/kimi-k2.6   # override model
kimiflare --reasoning                 # (print mode) stream chain-of-thought to stderr
```

Interactive slash commands:

| Command                     | Effect                                                                          |
|-----------------------------|---------------------------------------------------------------------------------|
| `/mode edit\|plan\|auto`     | Switch mode. `edit` prompts for permission (default), `plan` is read-only research, `auto` auto-approves every tool call. |
| `/plan` `/auto` `/edit`     | Shortcuts for the three modes.                                                  |
| `/thinking low\|medium\|high` | Reasoning effort. `low` = fastest, shallow; `medium` = balanced (default); `high` = deepest, slowest. Saved to config. |
| `/theme NAME`               | Switch color scheme: `dark` (default), `light` (bright terminals), `high-contrast`. Saved to config. |
| `/resume`                   | Pick a past conversation to restore.                                            |
| `/compact`                  | Summarize older turns to free context. Suggested automatically at ~80% full.    |
| `/reasoning`                | Toggle chain-of-thought display.                                                |
| `/clear`                    | Reset the current conversation.                                                 |
| `/cost` `/model` `/update`  | Info commands.                                                                  |
| `/logout`                   | Clear saved credentials.                                                        |
| `/help` `/exit`             | List commands / quit.                                                           |

Keys: `Shift+Tab` cycles mode · `Ctrl-R` toggles reasoning · `Ctrl-O` toggles verbose tool output · `Ctrl-C` interrupts an in-flight turn (press again to exit) · `↑`/`↓` walks prompt history.

### Modes

- **edit** — default. The agent calls tools freely for read-only work; mutating tools (`write`, `edit`, `bash`) pause for your approval.
- **plan** — read-only. Mutating tools are hard-blocked. Ask "plan a refactor" and the agent will investigate and produce a plan without touching the filesystem. Exit plan mode to execute.
- **auto** — autonomous. Every tool call is auto-approved. Use for trusted, well-scoped tasks.

### Thinking level (quality vs speed)

Kimi-K2.6 always reasons, but you can cap the effort:

- **low** — fastest. Best for chat, small edits, running commands.
- **medium** — balanced (default). Solid reasoning on real edits without the latency of deep thinking on trivial prompts.
- **high** — deepest. Best for multi-file refactors, subtle bugs, architectural decisions.

Set with `/thinking medium` (persists), or per-launch via `KIMI_REASONING_EFFORT=high`.

### Type-ahead queue

You can type the next prompt while the model is still executing. Submitted prompts show up as `⏳ …` and fire in order as each turn completes. `Ctrl-C` aborts the current turn and clears the queue.

### Session persistence

Sessions are saved to `~/.local/share/kimiflare/sessions/` after each turn. `/resume` lists the most recent (with first prompt + message count) so you can pick one up later.

### Task panel

For multi-step requests, the agent can publish a live task list via the `tasks_set` tool. The panel shows progress inline with status icons (`■` active, `☐` pending, `✓` done), elapsed time, and tokens consumed for the current task batch. Press `Ctrl-O` while a turn is running to switch tool output between compact (first line) and verbose (full output) modes.

### Paste collapse

Paste a large block (≥ 200 chars or ≥ 3 newlines in one paste) into the prompt and the input collapses it to `[pasted N lines #id]`. The full content still goes to the model on submit — only the on-screen display and chat history are collapsed, so scrollback doesn't get buried by a wall of code.

## Why

- **262k context.** Read entire modules without pagination.
- **Native tool use.** File I/O, shell, globs, grep, web fetch — all wired up, with per-call approval for anything mutating.
- **Streaming reasoning + content.** The model's chain-of-thought streams separately; toggle with `/reasoning` or `Ctrl-R`.
- **Pay your own way.** Your Cloudflare account, your credits, your rate limits. `$0.95 / M input`, `$0.16 / M cached input`, `$4.00 / M output`. The bottom status line shows live cost.

## Tools

All tool calls show inline; mutating ones require per-call approval the first time, with an option to allow for the rest of the session.

| Tool        | Permission | What it does |
|-------------|------------|--------------|
| `read`      | auto       | Read a text file (≤ 2MB) with optional line range. |
| `write`     | prompt     | Create or overwrite a file. Shows a unified diff before you approve. |
| `edit`      | prompt     | Replace an exact substring. Fails unless `old_string` is unique (or `replace_all=true`). |
| `bash`      | prompt     | Run a shell command via `bash -lc`. Session-allow is keyed by the first token of the command. |
| `glob`      | auto       | Match files by pattern (`**/*.ts`), sorted by mtime. |
| `grep`      | auto       | Regex search. Uses `rg` if installed; falls back to a JS walk. |
| `web_fetch` | auto       | Fetch a URL, convert HTML → markdown (≤ 100KB). |

## How it works

```
           ┌───────────────────────────────────────────────────────────┐
           │ kimiflare (Node + Ink TUI)                                │
 user ─▶   │                                                           │
           │   user msg ─▶ agent loop ─▶ runKimi() ──[POST SSE]──▶     │
           │                       ▲                                   │
           │                       │                                   │
           │      tool result ◀──tool executor──◀ tool_calls           │
           │           (permission modal for write / edit / bash)      │
           └───────────────────────────────────────────────────────────┘
                                                          │
                                                          ▼
                                       api.cloudflare.com/client/v4
                                       /accounts/{ID}/ai/run/
                                       @cf/moonshotai/kimi-k2.6
```

No AI Gateway, no proxy, no OpenAI SDK. Direct `fetch` to Workers AI, OpenAI-compatible `messages` + `tools` payload, SSE stream with reasoning + content + tool-call deltas accumulated by index.

## Development

```sh
git clone https://github.com/sinameraji/kimiflare
cd kimiflare
npm install
npm run build
npm link          # or: ln -s "$PWD/bin/kimiflare.mjs" ~/.local/bin/kimiflare
```

## Status

Early but functional. Transport + tools + agent loop + print mode are verified end-to-end. Interactive TUI ships modes, themes, thinking levels, session resume, compaction, and type-ahead queue.

## License

TBD.

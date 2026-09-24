# UnSkilled

A minimal desktop coding-agent harness for Windows, macOS, and Linux, with the [skilled](../../README.md) workflow built in.

You open a project folder, start a thread, and work with Claude inside it. Typing `/` shows skilled's workflow skills (`/skilled-setup`, `/domain-interview`, `/implement`, …). The agent picks up skilled's design and review skills (`tdd`, `review-diff`, `release-safety`, …) by itself as the work calls for them.

## How skills get in without costing context

The app follows the contract in [HARNESS.md](../../HARNESS.md):

- **Model-invoked skills (15)** go to Claude as a local plugin, generated into the app's data folder from the bundled `skills/`. Claude lists them and loads each one only when it needs it. Inside a plugin they are named `skilled:<name>`, so the app rewrites every `Call the Skill tool with "x"` in the plugin's copies to match.
- **User-invoked skills (23)** never go to the agent. The `/` menu lists them from `skills.json`. When you pick one, the app puts the skill's body into your message, the same thing Claude Code does for a typed `/command`.
- **git-guardrails** runs as a pre-tool hook on every shell command the agent issues. It needs Python 3; without it the guard is off.

## Library

The Library (⌘⇧L, the books icon in the sidebar, or ⌘K) shows what the agents get, like the plugin and skill views in other harnesses:

- **Skills:** every skilled skill, searchable, split into the workflow skills you start with `/` and the ones the agent loads by itself. Each one shows its full SKILL.md, what it calls and what calls it, its files, and how it reaches each installed agent (Claude's plugin, Codex's skills folder, `DSH_BUNDLED_SKILL_DIR`, or `install.py`). Workflow skills have a **Use in Thread** button.
- **MCP Servers:** your own servers, the app's built-in browser tools, and, read-only, the servers each agent already loads from its own config: Claude Code's `~/.claude.json` and `.mcp.json`, Codex's `~/.codex/config.toml`, Gemini's `settings.json`, and OpenCode's `opencode.json`. Env and header values are never shown.
- **Agents:** every agent the app knows, installed or not, with how it runs, how skills and MCP servers reach it, and a copyable install command for the missing ones.

### Your MCP servers

Add a server in the Library (a command, or a URL for Streamable HTTP, plus env vars or headers) and every agent gets it in every thread, next to its own:

- Claude gets it through the Agent SDK's `mcpServers`.
- Codex gets it in the thread's config (`mcp_servers`).
- ACP agents get it in `session/new`. They get stdio servers always, and URL servers when they support HTTP MCP.

Changing the list reloads the agent's session at the next message, so a running conversation picks it up. **Test** connects and lists the server's tools. Switching a server off keeps it without passing it on. The servers live in `mcp.json` in the data folder, in the same shape as Claude Code's `.mcp.json`, so entries copy across; the file is readable only by you.

## Command palette

⌘K (Ctrl+K on Windows and Linux) opens one search box over everything: actions (new thread, the side panel's tabs, permission mode, agent, model, theme), skilled's workflow skills, every thread in every project, and the projects themselves. Arrow keys move, Return runs, Esc closes. With nothing typed it shows the actions and your five most recent threads. Picking a skill puts it in the current thread's message box, or starts a thread with it when none is open.

## Settings

Settings (⌘, or the gear in the sidebar) is one sheet:

- **Appearance:** System, Light, or Dark.
- **New threads:** the agent and permission mode a new thread starts with.
- **API keys** for Anthropic, DeepSeek, and OpenAI. They're encrypted with the OS keychain (Electron `safeStorage`), never sent to the window, and passed only as `ANTHROPIC_API_KEY`, `DEEPSEEK_API_KEY`, or `OPENAI_API_KEY` to agent processes. A key saved here wins over the same variable from your shell. Saving or removing one restarts running agents.

- **Updates:** the version, and whether new ones download by themselves (on by default).

The thread header shows one quiet meter: the thread's tokens and cost so far, summed from each finished turn.

Beside it, a limit meter shows how close the thread's agent is to its plan's rate limits (Claude's 5-hour and weekly windows, Codex's windows), once one passes 50%. It turns orange from 80% and red when a limit is hit, with reset times on hover. The app never asks for these: Claude Code sends a `rate_limit_event` and Codex an `account/rateLimits/updated` notification, both built from the headers on responses the agent gets anyway. There's no polling, and no call to Claude's usage endpoint or Codex's `account/rateLimits/read`, so watching the limits can't use them up. The numbers are only as fresh as the agent's last turn; API-key logins have no plan limits, so they show none.

## Terminal

The Terminal tab (⌃\`) is a real shell in the project folder: `$SHELL` on macOS and Linux, and PowerShell 7, Windows PowerShell, or cmd on Windows. It runs through node-pty and xterm.js, with one shell per project that keeps running while you switch tabs. If the shell exits, press any key to start a new one.

## Agents

Every thread runs one agent, picked in the header. Switching agents starts a fresh conversation, because sessions don't carry across agents.

- **Claude** (always there) uses the Claude Agent SDK. It gets skilled's model-invoked skills as a plugin, plus the browser tools.
- **Codex** appears when `codex` is on your PATH. It runs as `codex app-server`, one process for all threads, and resumes threads from Codex's own history. It uses your Codex login. skilled's model-invoked skills reach it as an extra skills root, and Ask / Auto-edit / Full map onto Codex's approval policy and sandbox (`untrusted` / `on-request` / `never`, with `workspace-write`, or full access in Full). Once you open the browser tab, the thread gets the browser tools as an MCP server in its config. A thread that's already running is reloaded so it picks them up.
- **Any agent that speaks ACP** (the [Agent Client Protocol](https://agentclientprotocol.com)) goes through one generic driver. Each thread keeps its agent process alive between turns and resumes the stored session after a restart when the agent supports it. Models come from the agent's own `model` config option.
  - **DeepSeek** appears when `dsh` ([deepseek-harness](https://github.com/deepseek-ai/deepseek-harness), `npm i -g @deepseek-ai/dsh`) is on your PATH. It runs as `dsh --profile acp` and uses your dsh configuration and `DEEPSEEK_API_KEY`. skilled's model-invoked skills reach it through `DSH_BUNDLED_SKILL_DIR`, so nothing is written into your project.
  - **Gemini** appears when `gemini` ([Gemini CLI](https://geminicli.com/docs/cli/acp-mode/)) is on your PATH, and runs as `gemini --acp`.
  - **OpenCode** appears when `opencode` is on your PATH, and runs as `opencode acp`.
  - **Cursor** appears when `cursor-agent` is on your PATH.
  - Gemini, OpenCode, and Cursor have no setting for an extra skills folder, so skilled's model-invoked skills reach them only if you run `python3 install.py --model-only` in the project (they read `.agents/skills`). The `/` menu works for them either way.
  - **Your own:** add them to `agents.json` in the app's data folder. An entry with a preset's id replaces the preset:

    ```json
    { "agents": [{ "id": "qwen", "label": "Qwen Code", "command": "qwen", "args": ["--acp"], "env": {} }] }
    ```

  The permission modes carry over. Ask asks for every tool call. Auto-edit allows reads and file edits without asking. Full allows everything.

The `/` menu works the same for every agent, since the app composes the skill's text itself. The browser tools reach Codex and ACP agents too (for ACP, if the agent accepts HTTP MCP servers; deepseek-harness does). The app serves them from a local MCP server on 127.0.0.1, which only accepts requests carrying a per-run token.

## The built-in browser

The Browser tab (⌘⇧B) is a real Chromium page beside the thread: open your dev server there, and the agent can drive the same page. Once you've opened the tab, the agent gets seven tools: `browser_open`, `browser_snapshot`, `browser_click`, `browser_type`, `browser_eval`, `browser_logs`, and `browser_screenshot`. Before that, they aren't sent at all, so they cost no context.

- Snapshots are text with element refs (`[e3] button "Sign in"`), a fraction of a screenshot's tokens. Screenshots are saved to files, and the model sees the image only when it asks.
- Clicks are real mouse events through the Chrome DevTools Protocol. Console errors, uncaught exceptions, and failed or 4xx/5xx requests are captured as they happen.
- `verify-in-browser` picks these tools up automatically, so a UI check runs where you can watch it.
- **Pick an element** with the target button: hover to highlight, click to add the element's selector, text, HTML, and a cropped screenshot to your message. Esc cancels.
- The pane has no Node access and no preload, and loads only http(s), file, and data URLs. `browser_eval` asks before it runs in Ask mode; the other tools don't.

## Running it

From the repo root:

```bash
pnpm install
pnpm dev          # Electron with hot reload
pnpm test         # unit tests
pnpm typecheck
```

Claude uses your existing Claude Code login (run `claude` once in a terminal), or `ANTHROPIC_API_KEY`. It reads your usual Claude Code settings and `CLAUDE.md`.

To look at the UI without Electron or an agent: `pnpm --filter unskilled preview:ui`, then open `http://localhost:5199/?state=thread`. Other states: `permission`, `running`, `project`, `welcome`, `settings`, `update`, `palette`, `limits`, `library`, `library-mcp`, `library-agents`. This uses canned data from `src/renderer/src/mock.ts`.

## Building installers

`pnpm --filter unskilled dist` builds for the OS you're on: a `.dmg`/`.zip` on macOS, an NSIS `.exe` on Windows, an `.AppImage` on Linux. The icon is `build/icon.png`, rendered from `build/icon.svg`.

To release, bump `version` in `apps/unskilled/package.json` on main, then either:

- push a tag `unskilled-v<version>`, or
- on GitHub, open Actions → release-unskilled → Run workflow, pick `main`, and tick **publish**. That tags the commit for you, and works from a phone.

The `release-unskilled` workflow builds all three, then publishes a GitHub release with the installers and the `latest*.yml` files the updater reads. It refuses a version that's already released. A manual run without **publish** only builds.

### Updates

Installed copies check this repo's latest GitHub release at start and every four hours, download a newer version in the background, and install it when you quit. The sidebar shows **Update ready · Restart** to install right away. It works in the macOS and Windows builds and the Linux AppImage, never in dev. On macOS it needs a signed build, because macOS refuses unsigned updates. Other releases in this repo must not be marked "latest", or the updater will look there and find nothing.

### Signing

Builds are unsigned until these repository secrets exist. Each OS signs only when its own are set.

| Secret | What it is |
| :--- | :--- |
| `MAC_CSC_LINK`, `MAC_CSC_KEY_PASSWORD` | A "Developer ID Application" certificate as a base64 `.p12`, and its password |
| `APPLE_ID`, `APPLE_APP_SPECIFIC_PASSWORD`, `APPLE_TEAM_ID` | For notarization. Needs the certificate above |
| `WIN_CSC_LINK`, `WIN_CSC_KEY_PASSWORD` | A code-signing certificate as a base64 `.pfx`, and its password |

The macOS build uses the hardened runtime with the entitlements in `build/entitlements.mac.plist`: JIT for V8 and the bundled Claude Code binary, and library validation off for node-pty.

CI runs typecheck, tests, packaging, and a smoke test of the packaged app on all three OSes. The smoke test (`--smoke`) checks that the window loads, the preload bridge works, the skills catalog and settings answer, the bundled Claude Code binary runs, the browser tools can open a page, type, click, pick an element, and read the console, and a real shell answers through node-pty. Set `UNSKILLED_SMOKE_SCREENSHOT=<file.png>` to also save a screenshot of the window. On Linux, CI also installs Codex, so `test/codex-e2e.test.ts` runs the real `codex app-server` against a fake model: it adds the browser tools mid-thread, then approves and runs one. `test/claude-e2e.test.ts` does the same for the bundled Claude Code binary against a fake Messages API, on every OS. Both fakes send plan rate-limit headers. The Codex test checks the limits arrive without any extra request; the Claude test checks an API-key session makes no extra request and shows no plan limits, since they don't apply to API keys.

## Layout

| Path | What it is |
| :--- | :--- |
| `src/main/index.ts` | Electron entry point: window, IPC, smoke mode |
| `src/main/service.ts` | Everything the UI can ask for. No Electron imports, so it runs in tests |
| `src/main/agents/` | The `AgentDriver` interface; the Claude (Agent SDK), Codex (app-server), and ACP drivers; the shared stdio JSON-RPC transport; and the agent registry |
| `src/main/skills/` | Reading `skills.json`, generating the plugin, composing prompts |
| `src/main/updater.ts` | Background updates from GitHub releases (electron-updater) |
| `src/main/mcp/` | Your MCP servers (`mcp.json`), each agent's format for them, the Test connection, and reading the agents' own MCP config |
| `src/main/library.ts` | What the Library shows: skill details and the agent catalog |
| `src/main/settings.ts` | Settings and encrypted API keys, in `settings.json` in the data folder |
| `src/main/db.ts` | SQLite store (`node:sqlite`): projects, threads, events |
| `src/main/git.ts` | Working-tree diff for the Changes panel |
| `src/main/mcp-http.ts` | The harness's tools as a local MCP server, for ACP agents |
| `src/main/terminal.ts` | The Terminal tab's shells (node-pty) |
| `src/main/browser/` | The browser pane's controller (DevTools Protocol), page snapshots, and the agent's `browser_*` tools |
| `src/main/guard.ts` | git-guardrails pre-tool hook |
| `src/preload/` | The `window.unskilled` bridge |
| `src/shared/types.ts` | The main ↔ renderer contract |
| `src/renderer/` | React UI. Hand-written CSS in `styles/app.css`, state in `store.ts`, the command palette's search in `palette.ts` |

## Stack

Electron 44 (the same Chromium on every OS, which the built-in browser needs), React 19, Vite via electron-vite, Zustand, `node:sqlite`, the Claude Agent SDK, and xterm.js with node-pty, the app's one native module. node-pty uses Node-API, so the same build works in Node and Electron. The UI uses no component library: system fonts, macOS vibrancy and Windows Mica, light and dark themes from CSS tokens.

## Roadmap

- **Milestone 2:** ~~the built-in browser pane~~, ~~the generic ACP driver~~, ~~browser tools for ACP agents and Codex~~, ~~the element picker~~, ~~Codex~~, and ~~the terminal tab~~ (done).
- **Milestone 3:** ~~settings~~, ~~a per-thread view of token usage~~, ~~an app icon~~, ~~auto-update~~, ~~signing and notarization~~, ~~the ⌘K command palette~~ (done).

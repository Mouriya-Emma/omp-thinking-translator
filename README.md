# omp-thinking-translator

An omp extension that translates visible assistant thinking blocks into another language for display only.

It renders one translation box directly below each visible assistant thinking block. If a translation finishes after its box can no longer be repainted, it emits a debounced in-flow transcript row at the current transcript tail. Translations stay in extension memory: they are never written to the session file, never part of the next model request, and never part of compaction input. See [Context Boundary](#context-boundary) for the mechanism, the runtime evidence, and what is explicitly not covered. The one file the extension does write is a diagnostic trace next to the session file (`trace` option below), which records the extension's own steps and never the session content.

## Features

- Translates the lines the host actually displays. The renderer receives the display text of each visible thinking block, and that text is the single source of truth for both what gets translated and where each translation is drawn — so a line the host rewrote (prose-only fence elision, empty reasoning-summary comments, streaming reveal) can no longer end up with no slot. That contract is pinned by a test that runs the host's own `formatThinkingForDisplay` over fenced and comment-bearing thinking and requires every still-displayed line to resolve back to its raw line.
- Gates per line, not per block: a line is translated when it contains Latin letters and more Latin letters than Chinese characters. A one-sentence thinking block right before a tool call is translated like any other.
- Translates while the block is still streaming. The host recreates the renderer on every display-text change, so each completed line is dispatched as soon as it appears — measured at 3 ms after `thinking_end` for a one-line block. A line is dispatched only once it is a complete line of an observed block: while the block is open its trailing line is still being revealed, and every revealed prefix would otherwise become its own request.
- Dispatches only lines of thinking blocks this process actually observed streaming, matched by content against every tracked block (`resolveTrackedLine`), and keys each cell by the **raw line it matched**, not by the display text. The host reveals a line character by character and the matcher tolerates a missing final period (the host's code-fence fold eats one), so the frame one character short of the period is already accepted as a complete line; keying by display text would translate that line twice — the box would show the second result while the first, never painted, surfaced as a stray late row. Block identity is deliberately *not* the host's `contentIndex`: every assistant message numbers its thinking blocks from 0, a tool result is its own message, and the previous message's thinking component keeps being repainted afterwards — so an index-keyed lookup hands that component the *next* block's raw text and the whole block silently goes untranslated. Replayed history matches no tracked block and is rendered without being re-translated.
- Retries a failing translation with backoff (500 ms, 2 s, 6 s) before giving up, treating an empty response as a failure. A translator model that is offline, rate-limited, or mid-restart therefore recovers on its own instead of leaving a permanent error row; the line stays silent until real text exists.
- Each box shows a `思考翻译 · 块 N · done/total` title (N counts thinking blocks within the same message) and only rows that already have translated text. Pending lines occupy no rows at all — progress lives in the title count — so a five-line block does not first expand into five placeholder rows, and no frozen placeholder is left behind in scrollback. A line that exhausted its retries shows a failure row. Translation updates repaint through the requesting component's own `requestRender`, and the effective config is only ever replaced, never cleared — otherwise the key material for the lookup vanishes and every box on screen blanks out the moment the host starts the next message, which a tool result also is.
- Emits late translations through `ctx.ui.notify` as one debounced, dim in-flow transcript row. This is the only extension-accessible surface that appends a real transcript row without entering LLM context or the session file. The row is intentionally placed at the current transcript tail — after any tool output that already arrived — rather than pretending it can sit under the frozen thinking block; consecutive flushes re-include the prior payload only while no host chat event could have broken `notify`'s identity coalescing.
- Supports a global config with per-project overrides.

## Requirements

- omp (`@oh-my-pi/pi-coding-agent`), verified with 18.2.0. The host build must provide `registerAssistantThinkingRenderer` and `modelRegistry.refreshDiscoverableProviders`.

This extension is omp-only, not a pi extension. It is built on omp's extension API: the translation box attaches through `pi.registerAssistantThinkingRenderer`, which upstream pi does not provide, and every import resolves against omp's `@oh-my-pi/*` packages rather than pi's own. Running it on pi would mean a different display surface, not a configuration change.

## Install

This extension is installed from git; it is not published to any package registry.

```bash
omp plugin install git:github.com/Mouriya-Emma/omp-thinking-translator
```

For local development, either load the extension file directly:

```bash
omp -e /absolute/path/to/omp-thinking-translator/extensions/thinking-translator.ts
```

or install from a local checkout:

```bash
omp plugin install /absolute/path/to/omp-thinking-translator
```

The manifest key is `omp.extensions`, and the pinned `@oh-my-pi/*` 18.2.0 packages live in `devDependencies` only: the host already provides them, so installing this extension adds no `@oh-my-pi` packages under the plugin directory.

## Quick Start

1. Install the extension:

   ```bash
   omp plugin install git:github.com/Mouriya-Emma/omp-thinking-translator
   ```

2. Create a global config template from inside omp:

   ```text
   /thinking-translator init --global
   ```

3. Edit the generated file:

   ```text
   ~/.omp/agent/thinking-translator.json
   ```

4. Point the extension at a translator model and enable it:

   ```json
   {
     "enabled": true,
     "translatorModel": {
       "provider": "deepseek",
       "id": "deepseek-v4-flash"
     }
   }
   ```

5. Check the effective config:

   ```text
   /thinking-translator status
   ```

The `provider` and `id` must match a model visible to omp, for example a model from the host model registry. Under `omp --profile <name>`, omp points the agent directory at `~/.omp/profiles/<name>/agent`, so the global config for that profile lives there instead.

## Commands

```text
/thinking-translator
/thinking-translator status
/thinking-translator init
/thinking-translator init --global
/thinking-translator init --project
```

- `/thinking-translator` and `/thinking-translator status` show the effective config, config file paths, and translator model availability.
- `/thinking-translator init` creates the global config, same as `/thinking-translator init --global`.
- `/thinking-translator init --global` creates `<agentDir>/thinking-translator.json` (default `~/.omp/agent/thinking-translator.json`) if it does not already exist.
- `/thinking-translator init --project` creates `<cwd>/.omp/thinking-translator.json` in the current project if it does not already exist.

The init commands write a disabled template and do not choose a model. You must explicitly set `translatorModel` and set `enabled` to `true`.

## Configuration

The extension never writes config files on its own; files are created only by the `init` commands, and built-in defaults apply until you override them. Files hold partial overrides that merge over the defaults:

1. Built-in defaults
2. Global config: `<agentDir>/thinking-translator.json`, where `<agentDir>` is `$PI_CODING_AGENT_DIR` when set, otherwise `~/.omp/agent` (default `~/.omp/agent/thinking-translator.json`)
3. Project config: `<cwd>/.omp/thinking-translator.json`

The project file is read after the global file, so it wins on every field it sets, including individual `translatorModel` subfields.

A complete config looks like this:

```json
{
  "enabled": true,
  "targetLanguage": "Simplified Chinese",
  "translatorModel": {
    "provider": "deepseek",
    "id": "deepseek-v4-flash"
  }
}
```

### Options

| Option | Type | Default | Description |
| --- | --- | --- | --- |
| `enabled` | boolean | `true` | Enables translation processing. If no `translatorModel` is configured, translation is skipped with a warning. |
| `targetLanguage` | string | `"Simplified Chinese"` | Target language passed to the translator model. Must be a non-empty string. |
| `translatorModel` | object | unset | Translator model reference: `{ "provider": "...", "id": "..." }`. Both fields are required for the reference to take effect. |
| `trace` | string \| boolean | `true` | Diagnostic record. `true` appends one JSONL record per step (`session_start`, `message_start`, `thinking_end`, `factory`, `dispatch`, `resolve`, `request`, `done`/`translateError`, `render` on every cell-state change, `painted`, `settled`, `lateFlush`, `reset`, `missingModel`) to `<session file without .jsonl>.thinking-translator-trace.jsonl` next to the session file; `--no-session` processes write nothing. A string sets an explicit path; `false` disables. |

`contentTypes` and `minLatinChars`, left over from older config shapes, are silently ignored: only thinking blocks are translated, and translatability is decided per line rather than by a block-length threshold.

If any config file fails to parse, the extension shows a one-time warning naming that path and forces `enabled` to `false`, so nothing is translated under a broken config. If translation is enabled but `translatorModel` is missing, the extension warns once and skips translation without affecting the main assistant message. If the model is configured but not currently in the host model registry (typical for `discovery: proxy` providers, whose models the host only re-discovers for the main model and drops from the registry on cache invalidation or static reload), the extension asks the host to re-discover that provider (`refreshDiscoverableProviders`, at most once per provider per 60 s) and looks the model up again; if it is still missing it warns once and keeps retrying on later thinking blocks instead of skipping for the rest of the session. `/thinking-translator status` runs the same discovery before reporting `model:`. A translation request that keeps failing after its retries leaves the original thinking untouched and surfaces the error inside that line's row.

## How It Works

1. The extension tracks thinking blocks as it sees them stream: `message_start` reloads the effective config and bumps the message counter, `message_update` records each block's raw text under `message:contentIndex` (marking it closed on `thinking_end`), and `message_end` closes whatever the provider left open so its trailing line can still be translated. Records are kept across messages — the previous message's thinking component is still being repainted — and bounded to the most recent 32 blocks. Note that a tool result is its own message, so `message_start` fires mid-turn, which is why the config is replaced there rather than cleared.
2. The host resolves the display text of every visible thinking block and calls the registered renderer factory with it, again on every change to that text.
3. On each render the extension splits that display text on newlines, trims the lines, and keeps those with Latin letters.
4. Each line is checked against the per-line gate and against every tracked block: it must be a complete line of one of them, where "complete" means followed by a newline, or by the end of a block that has closed. A half-written line still being revealed therefore waits instead of being translated as a stream of throwaway fragments, and replayed history — which matches no tracked block — is never dispatched.
5. Each line text is translated at most once per translator model and target language: the first dispatch creates its slot and fires one independent streaming request, and every later render reuses that slot. Slow lines never block their siblings, and every line lands back in original order.
6. `render()` looks each displayed line up in the table and draws the box beneath that block with a `done/total` title and one row per line that already has text. A failing request is retried with backoff (500 ms, 2 s, 6 s) and only then becomes a failure row. Every translation arrival or failure calls the host-provided `requestRender`, so a box the host still renders keeps filling in and recounting.
7. When a translation completes, the extension checks whether the box ever drew that cell. If not, it queues the text for a short debounce and emits one `ctx.ui.notify` payload containing the queued translations and a `思考翻译 · 第 N 块` header. A repaint before the flush marks the cell painted and removes it from that payload. If no host chat event intervened, the next notify re-includes the previous payload because the host may otherwise replace the same status row; `message_start`, `message_update`, or `message_end` starts a fresh payload after chat content has mounted or changed.
8. Translations live only in an in-memory table and are dropped on session start, session switch, and session shutdown, together with the pending notify queue and prior payload. Nothing is appended to the session transcript and no translation is ever fed back as model input; see [Context Boundary](#context-boundary).

## Context Boundary

The translation box is presentation output, not conversation content. The canonical assistant thinking — what omp persists, sends on the next turn, and feeds to compaction — stays the original text the model produced.

Mechanism:

- Translations live in a module-local `Map` keyed by the raw thinking line plus translator model and target language (`extensions/thinking-translator.ts:104`, `cellKey` `:486`), read only by the component returned from `pi.registerAssistantThinkingRenderer` and by the in-flow notify fallback (`extensions/thinking-translator.ts:130-190`, `:202-235`). Those rows flow into the TUI container tree and terminate at the terminal write; on host 18.1.19 no consumer of them reached a session writer, the provider request builder, or compaction (`assistant-message.ts:841-860` → `pi-tui/src/tui.ts:486-513` → `tui.ts:2735-2781`), and 18.2.0's `#appendThinkingExtensions` (`assistant-message.ts:841-860`) still hands the renderer a fresh context object and only mounts the returned component.
- The `context.text` handed to the renderer is a resolved display string in a freshly allocated object (`assistant-message.ts:841-852`), not a reference into the stored `AgentMessage`, so a renderer cannot mutate the message through it.
- Persistence writes typed `SessionEntry.message` values to the session JSONL (`session-manager.ts:2288-2305`, `:817-818`); the next request is rebuilt from those entries (`session-context.ts:216-272`, `agent-loop.ts:1627-1673`); compaction partitions the same branch entries (`compaction.ts:1328-1382`). None of the three reads rendered rows.
- The hooks that can change model-visible data in this host are `context`, `before_provider_request`, `before_agent_start`, `session_before_compact`, and `session_stop`. The extension registers none of them; its only handlers are session reset, per-message state tracking, chat-content generation, and the thinking-block bookkeeping in `message_start`/`message_update`/`message_end` (`extensions/thinking-translator.ts:266-370`).

The original context-boundary checks below ran on omp 18.1.19, driving the real TUI with a throwaway read-only observer extension attached to `before_provider_request` (the final pre-send payload hook) and `session_before_compact`, using high-entropy fragments of the rendered Chinese plus the box labels `思考翻译` / `等待翻译` / `翻译失败` as canaries. The notify-specific check was repeated on omp 18.1.21 as described below:

- **Next turn, before any compaction.** The provider payload of the turn that directly followed a completed translation box carried the assistant `thinking` part unchanged (5209 chars, SHA-256 `068c357d54f0d1b0b84453a10c2a3c5c2acc445d2d116b1f39d1dd34f1923b55`) plus its text; a recursive scan of every string in the serialized payload counted 0 occurrences of every canary. This request was observed before any compaction ran, so nothing ephemeral could have been stripped by it; a second run showed the same for its own pre-compaction turn (assistant `thinking` 4491 chars, SHA-256 `e9cb8a43…`, 0 canaries).
- **Compaction input.** A `/compact` whose summarized set contained the translated block — `messagesToSummarize` = 13, `messagesToSummarize[0]` the same assistant message with the identical thinking hash — had 0 canary occurrences in the whole `CompactionPreparation`, in the 3958-char summary omp then persisted, and in the following provider payload.
- **Session store.** Structural scan of every record, message, and content part of the target session JSONL: 0 canary occurrences, and the persisted thinking hash equals the one sent to the provider. `agent.db` holds settings/auth/usage tables, not transcript messages, and its raw file plus WAL/SHM also had 0 occurrences.
- **Notify runtime.** A real omp 18.1.21 TUI run with this checkout loaded through `-e` produced a 4650-character thinking block followed by a `read package.json` tool call. The TUI showed the checkout's in-flow `思考翻译 · 第 1 块` row; a structural scan of the resulting session JSONL found zero occurrences of that header, `全面分析如何安全地检查该TypeScript项目`, or any notify payload.

Minimal reproduction:

1. Write a throwaway extension that registers `pi.on("before_provider_request", ...)` and `pi.on("session_before_compact", ...)`, appends `JSON.stringify` of the payload and of `event.preparation` to two files, and returns `undefined` from both handlers.
2. Start `omp -e /path/to/extensions/thinking-translator.ts -e /path/to/observer.ts` in a scratch directory.
3. Send an English prompt that produces a multi-line thinking block, and wait until the box reads `思考翻译 · 块 N · M/M`. Copy two distinctive fragments of the rendered Chinese — they must not occur in the prompt or in the thinking itself.
4. Send another turn, then search the newest `before_provider_request` payload recursively for those fragments and for the three box labels. Expect zero, and expect the assistant `thinking` string to hash to the same value the session JSONL stores.
5. Add filler turns until `/compact` reports a non-empty `messagesToSummarize`, run it, and search the recorded `preparation` and the persisted compaction summary the same way. Expect zero while the summarized assistant message still carries the original thinking hash.
6. Parse the session JSONL and search every content part. Expect zero.

Not covered by this boundary:

- **The translation request itself.** Each eligible thinking line is sent to the configured translator model as its own standalone request (`extensions/thinking-translator.ts:403-484`), separate from the agent conversation. "Not in the agent context" does not mean "not sent to any model": that provider sees your thinking text and retains it under its own policy.
- **Display-derived artifacts.** Terminal scrollback, in-flow notify rows, a terminal recorder, and omp's own `/debug-transcript` (which dumps rendered rows to a temp file, `command-controller.ts:225-236`) contain translated rows by design. That is an observability surface, not conversation context.
- **Untested paths.** The compaction check ran on a resumed persisted session, so resume is covered to the extent that its canonical messages, provider payloads, and compaction input were inspected — not that historical translations re-render or that every resume UI path was exercised. Session export/import serializers and branch switching were not exercised at all.
- **Version scope.** The evidence is for this extension revision on omp 18.1.19 (notify check repeated on 18.1.21). The guarantee rests on the host renderer contract and on the request/compaction paths cited above, not on a documented API promise, so re-verify after a host upgrade; the current pin is 18.2.0 and the code paths were re-read there, but the canary runs were not repeated.

## Limitations

- If a thinking block is not visible (for example folded away by the host so it never renders), the host never invokes the translation renderer and no box appears for it.
- Diagnostics: every session-saving process appends `<session file without .jsonl>.thinking-translator-trace.jsonl` beside the session JSONL (see the `trace` option). It contains event names, line counts, the first 40–60 characters of each source line and translation, model ids and file paths — enough to see where a session's translation stopped. Set `trace: false` if that is not acceptable.
- Terminal scrollback is immutable. The host commits a thinking block's rows once the assistant message reaches its tool call, and after that the box is frozen at whatever it showed — measured: a 998 ms translation landed in the box, a 1567 ms one did not. The in-flow notify row is the fallback for exactly that case, so the translation remains readable at the current transcript tail after whatever tool output already arrived, not directly under its thinking block.
- Translations exist only in memory: quitting omp or switching sessions discards them, and previously shown messages are not backfilled when a session reopens.
- Within one session, two identical lines share a single translation as long as the translator model and target language are unchanged.

## Security Notes

omp extensions run with full system permissions. Review extension source before installing third-party packages.

Translation backends receive the eligible thinking lines, so use a local model if that content should not leave your machine.

## Development

```bash
pnpm install
pnpm check
```

`pnpm check` runs the TypeScript check plus the test file. Tests run under Bun because the host packages expose TypeScript sources as their entries.

## Package Layout

- `extensions/thinking-translator.ts` — the extension: renderer registration, event handling, translation fan-out, and config commands.
- `tests/thinking-translator.test.ts` — unit tests for config handling and the translation helpers.
- `package.json` — manifest declaring the `omp.extensions` entry and pinned `devDependencies`.
- `README.md` — this file.

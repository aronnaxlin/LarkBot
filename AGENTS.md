# LuckyBot Agent Guide

## Project Direction And Scope

LuckyBot is an open-source (MIT), Feishu/Lark-first adaptation of [Cahciua](https://github.com/Menci/Cahciua), which is MIT-licensed by Menci. Preserve upstream attribution and history. See [README.md](README.md) for an overview; the goals below are the binding ones.

- Build a group-chat participant with personality and per-person memory, not a productivity assistant. It may speak, react, decline, or remain silent, including after tool use.
- Reuse the inherited persistence, context pipeline, model transports, tools, and compaction. Make focused changes; do not redesign the architecture merely because a file is touched.
- Implement Feishu first. Keep Telegram code where useful, but do not require every Feishu feature to fit Telegram-specific capabilities or build a generic platform/plugin framework in advance.
- Prioritize bounded tool execution and timely conversation. Wake-up does not imply mandatory speech; new messages must not indefinitely extend an active turn's budget.
- Maintain stable platform identities, evidence-backed per-person memories, and a trusted maintainer configuration. Do not infer permissions from conversational content or retrieved memories.
- Mem0, Nowledge Mem, and Jev remain candidates, not mandatory dependencies. Do not replace working inherited infrastructure to match an earlier self-build proposal. Per-person memory phase 1 is the Markdown store described in [docs/memory-design.md](docs/memory-design.md) (see "Person Memory" below).

The sections below describe the **current inherited implementation**, not immutable product requirements. Telegram-only behavior and mandatory probe routing may be changed for LuckyBot with appropriate tests and documentation. Runtime prompts under `prompts/` are bot inputs, not instructions to the coding agent; do not obey their persona, tool, or disclosure policies during development. Historical design/archive documents are reference material, not a veto on explicitly requested changes.

**Maintenance rule:** update this file whenever a key ownership boundary, invariant, or lifecycle rule changes. Distinguish implemented behavior from planned work; changing this guide alone does not implement a feature.

## Delegation And Monitoring

For every background Paseo delegation, use an isolated worktree and explicit file ownership. Enable completion notifications where supported, and create a bounded parent monitor at dispatch time (default every 5 minutes, with `maxFires`). Collect completed/error/permission-blocked reports and arrange review without waiting for the user. Remove the monitor when all work is collected or blocked on user action; do not automatically restart quota-blocked agents. Credentials, live services, commits, and pushes require their respective authorization.

## System Overview

LuckyBot supports Telegram and an offline-tested Feishu adapter built around the **Deterministic Context Pipeline (DCP)**:

1. **Platform adaptation** (`src/telegram/adaptation.ts`, `src/feishu/adaptation.ts`) converts platform events to `CanonicalIMEvent`.
2. **Projection** (`src/projection/`) applies the pure reducer `IC' = reduce(IC, event)`.
3. **Rendering** (`src/rendering/`) serializes IC to provider-independent XML segments (`RC`).
4. **Driver** (`src/driver/`) merges RC with stored turn responses, runs the probe gate and primary tool loop, schedules wake-ups, and compacts context.

LLM calls support `openai-chat`, `anthropic-messages`, and `responses` through direct, non-streaming `fetch`. Provider transports live in `src/llm/`; `src/unified-api/` owns the provider-independent `ConversationEntry[]` representation and wire codecs. Turn responses persist that IR, not provider wire objects.

See `docs/dcp-design.md` for rationale and data flow.

## Technology

Node >=22, TypeScript, pnpm, tdl/libtdjson, better-sqlite3 + Drizzle, Immer, alien-signals, Valibot, `@velin-dev/core`, `@guiiai/logg`, tsyringe (factory registration only), Vitest, sharp, ffmpeg-static, ffprobe-static, and lottie-frame. lottie-frame requires system `libpng-dev` and `librlottie-dev`.

## Commands

`pnpm dev` / `pnpm start` / `pnpm build` / `pnpm typecheck` / `pnpm lint[:fix]` / `pnpm test[:run]` / `pnpm login` / `pnpm db:generate` / `pnpm tdlib:build` / `pnpm tdlib:types`.

## Ownership

```text
src/
├── adaptation/   Canonical event/content types and platform-neutral content helpers
├── projection/   Pure IC reducer
├── rendering/    IC -> XML RenderedContext
├── unified-api/  Provider-independent LLM conversation IR and codecs
├── llm/          Non-streaming provider transports, request prep, request dumps
├── media/        Thumbnails, frame extraction, alt-text resolvers, media runtime
├── driver/       Scheduling, probe/primary wake-up, runner, tools, compaction
├── memory/       Per-person Markdown memory: store, consolidator, controller, injection
├── telegram/     TDLib clients, manager, adaptation, ingress/egress adapters
├── feishu/       Official SDK boundary, credentials, group ingress and outbound
├── event-sink.ts Shared canonical event persistence/publication
├── container/    Typed tsyringe tokens and statically imported registrars
├── startup/      Replay and application lifecycle orchestration
├── db/           Drizzle schema and persistence
├── config/       YAML parsing and resolution
├── pipeline.ts   Per-chat IC/RC residency
└── index.ts      Thin process entry point
```

Platform types (`Attachment`, `MessageEntity`, etc.) live in `src/telegram/message/types.ts`. Canonical types live in `src/adaptation/types.ts`. Canonical IDs are strings. Imports are relative; no tsconfig aliases.

## Dependency Injection And Lifecycle

The composition root uses tsyringe without decorators or constructor injection. Services remain closure factories. `src/container/index.ts` statically imports every registrar so tsdown can trace the complete graph; filesystem discovery, glob imports, and side-effect registration are forbidden.

Registrars use typed symbol tokens and `instancePerContainerCachingFactory`. Business factories never receive the container. Resource shutdown is owned by startup, because factory providers are not automatically disposed by tsyringe.

Construction order breaks cycles explicitly:

- Telegram clients are created before the media runtime; custom-emoji resolution depends directly on the bot client.
- TelegramManager is created after media resolvers.
- Event producers publish through `DriverInputBus`, not a mutable Driver reference.
- Driver is attached before Telegram start, but the bus buffers the latest RC per chat until activation.
- Memory deps (`MEMORY_DEPS`: the Markdown backend plus DB closures for window, count, evidence and cursor) are built by the memory registrar after the Pipeline and handed to `createDriver`; business factories never receive the container.

Startup selects a lazy platform runtime: build container and migrate DB -> prepare platform identity -> cold replay -> attach Driver and ingress -> start selected platform -> activate Driver -> recover background tasks -> seed current RC -> platform post-startup. Feishu mode does not initialize TDLib or require Telegram credentials.

Shutdown is idempotent: deactivate Driver input -> stop Driver -> checkpoint background tasks -> stop the selected platform -> close SQLite -> dispose the DI container.

## Core Invariants

### Purity And Forward Flow

Projection is pure and performs no I/O. Only IM/runtime events enter Projection. Driver owns turn responses. External memory/profile data enters through late-binding prompts, never by mutating IC.

### Dual Timestamps

Every canonical event carries:

- `receivedAtMs`: local ingress time captured before asynchronous transforms; ordering source of truth.
- `timestampSec`: platform server time shown to the model.
- `utcOffsetMin`: local offset captured at ingress for rendered timestamps.
- A `receivedAtMs` more than 120 s after `timestampSec` adds a `received="<local time>"` attribute to the rendered `<message>`; Feishu retries delivery after disconnects (observed 2026-10-17: about 5 min, 1 h and 6 h late with the original `timestampSec`). The message stays ordered by arrival, and the attribute tells the model it is new despite the old `t`.

DB replay orders by `(received_at, id)`.

### Rendered Identifiers

Rendering compacts the chatlog without losing what the model needs; every rule is per-element and depends only on that element (and earlier ones), so appending new messages never rewrites the rendered prefix and prompt caches stay valid:

- **Message aliases.** When `RenderParams.aliasMessageIds` is set (the pipeline enables it for Feishu, whose `om_...` ids are 34 chars; Telegram keeps its short numeric ids so message deep links stay valid), every message id is rendered as a short alias (`m` + 9 base36 chars) in `<message id>`, `<in-reply-to id>`, attachment `file-id`, `message_pinned`, and blocked/deleted variants. The alias is `H(chatId, messageId)` from `src/rendering/aliases.ts` — deliberately not a position index, because cold replay starts at the compaction cursor and would renumber, and pure hashing is reproducible from persisted history. `assignMessageAliases` handles hash collisions deterministically: the first message in context order keeps the alias and the later one falls back to its canonical id. That fallback is the one case where an existing message's rendered id can change — if a restart replays the colliding pair in a different order, the winner can flip; at 46 bits no collision is expected in practice. Canonical ids remain valid tool input; the driver resolves each alias through the live IC, falling back to a narrow `message_id` scan of persisted history for messages the IC no longer holds (and skipping both when `aliasMessageIds` is off), before `messageExists`, any platform call, or `read_old_messages`. `primary-tools` memoizes resolution for one wake-up, and `send_message` echoes the alias the chatlog shows. `read_old_messages` re-renders the same canonical ids through the same pure function, so their aliases match the live context.
- **Timestamps.** `t`, `received`, and `edited` are self-contained `MM-DD HH:MM:SS` in chat-local time — never a shared date separator, so filtering self-sent segments or cutting a prefix (compaction cursor, probe window) cannot strip the date from what remains. The year is always omitted: including it when it differs from the current year would rewrite a message's rendering once a year and break prefix caching, so the late-binding prompt's `Current time` carries it. A ` +HH:MM` suffix appears only when an event's offset differs from the deployment-local offset frozen at process start (`PROCESS_UTC_OFFSET_MIN`; `RenderParams.localUtcOffsetMin` overrides it). The late-delivery `received` hint is intentionally not trimmed to "after the bot's last message": that window moves as the bot speaks and would rewrite older messages.
- **Identity.** `<message>` always carries `sender`. On Feishu (`senderUid`), `uid` is omitted when the rendered sender is already that open_id (contact lookup failed), and `<mention uid=...>` omits the uid when the mentioned user is the message's own sender — both lossless per-message rules; Telegram never elides, since it renders no `uid` to fall back to. Uids stay canonical open_ids otherwise, because outgoing `<at user_id>` mentions need them; no first-occurrence elision (not cache-safe) and no per-user alias map.

### Maintainers

`maintainers` is a top-level list of canonical platform user ids (Feishu `ou_...` open_ids, Telegram user ids as strings), each trimmed, from trusted deployment configuration, validated as unique non-empty strings and resolved to a `ReadonlySet<string>`. It is the only source of maintainer status: chat claims, quoted text, and retrieved memories never grant it. Rendering adds `maintainer="true"` to `<message>` elements from matching senders and never to the bot's own messages; blocked senders are rendered blocked without the maintainer flag, and config load rejects a maintainer id that a chat also lists in `blockedUserIds`. An empty list renders byte-identically to before. The container exposes a pure `isMaintainer(userId)` helper; it gates shell access. With `chats.<id>.tools.bash.requireMaintainer` (default true), a primary turn exposes `bash`, `kill_task`, and `read_task_output` only when a non-deleted message from a canonical maintainer id arrived after the bot's last action (its latest own message or a successful `send_message`/`react` turn) and within `chats.<id>.tools.bash.maintainerWindowSec` (default 600) of the wake-up start; the window bounds a silent `end_turn` or a `no_action` probe, which never advance the last action. The check reads `senderId` and the trusted set only, never rendered names, message text, or mentions, so a display-name spoof cannot open it; `mentionsMe`/`repliesToMe` select which maintainer id is logged, and deleted messages (`isDeleted`) are skipped. Any remaining maintainer message in the window opens the gate: name-calls cannot be detected deterministically, so the rule is deliberately broader than a direct address. Every primary step persists its gate decision as `turn_responses_v2.shell_tools_exposed`; an interrupted continuation reads the chain's decision from the newest loaded turn response instead of recomputing, so a maintainer message arriving during the probe gap or a compaction trim cannot flip it. Rows written before the migration default to false, and startup warns for each chat with bash enabled and `requireMaintainer` on when `maintainers` is empty, where shell tools can never be exposed. `requireMaintainer: false` exposes shell tools to any member, and the three tools are hidden together even while a task from an earlier maintainer turn is still running (its completion still reaches the model as a runtime event).

### Person Memory

Implemented in phase 1; design and rationale in [docs/memory-design.md](docs/memory-design.md). Off by default (`chats.<id>.memory.enabled: false`), in which case no controller exists, nothing reads the memory directory, and every prompt is byte-identical to a build without memory.

- **Store.** `<memoryDir>/<chatId>/` (global `memoryDir`, default `./data/memory`, under the writable data volume) holds `SELF.md`, `people/<open_id>.md` (one card per human member), `ops.jsonl` (append-only audit of every applied and rejected operation) and `forgets.jsonl` (owner-removal tombstones, trimmed to `doNotReadd` lines). Entries are `- [YYYY-MM-DD] [alias, …] text`, separated by a line that is exactly `§`. Ids are validated against `^[A-Za-z0-9_-]{1,64}$` before any path is built; no code path reads two chats. Maintainers edit the files by hand: the drift guard treats the on-disk entries as authoritative, rewrites canonically only on a real change, drops a file's ops if its hash changed since it was read, and never overwrites a file it cannot parse.
- **Writer.** `src/memory/controller.ts` (one per enabled chat, built in `createChatMemory` beside the compaction controller) triggers a consolidation when the DB count of human messages (not the bot, not self-sent, not other bots by the event's own `sender.isBot` — the `users` table is Telegram-only —, not blocked) since the memory cursor reaches `triggerMessages` (counted at most once per 30 s), or on a compaction (a flush heuristic: windows with fewer than 5 human messages skip the model call). The window starts at the **memory cursor** (table `memory_cursors`; never the compaction cursor) and is built from the DB archive into a throwaway IC, never the Pipeline IC; the cursor moves to the newest processed event's `receivedAtMs` only after files and audit lines were written. A run never blocks a wake-up. Failures latch with 5→60 min backoff; three consecutive output-validation failures on the same cursor skip the window (logged at `warn`, stored in `last_error`); provider errors never skip.
- **Validation is code, not prompt.** The model emits `add` / `owner` / `supersede` ops with cited message ids; the code writes the date (local date of the newest cited message) and the aliases. Every op needs in-window evidence (`SELF.md` included); other bots', blocked senders' and deleted messages cannot be cited. Third-party material about a person can only be stored with the `群里的说法：` prefix; `owner` replace/remove of a plain entry needs a message from the card's owner; `supersede` is the only way to touch hearsay and to upgrade it. Duplicates (same source class), recently forgotten facts of the same person, and the write-time scan (`src/memory/scan.ts`, a backstop with a code-constant blocklist) reject single ops.
- **Eviction is automatic.** The model cannot evict. When a file exceeds its budget (`cardMaxChars` 1200 / `selfMaxChars` 1000; hearsay capped at `hearsayMaxEntries`/`hearsayMaxChars`), the code drops hearsay oldest first (a hearsay entry added by the same batch is rejected instead), then owner entries oldest first only up to the net growth of this batch's owner-evidenced ops, else rejects the file unchanged. Hearsay can never evict an owner fact. Evictions are logged as `intent:"evict"`; they are not tombstoned. An evidence sweep removes entries whose evidence is positively deleted (an unresolvable alias never counts as deleted); it only runs on the files a run loads (`SELF.md` and the window's speakers), so a member who stays silent keeps such entries until they next speak in a consolidated window — there is deliberately no read-time sweep. Any removal backed by the card owner's own message is tombstoned in `forgets.jsonl` (hearsay prefix stripped), and re-adds are rejected when the new text contains or is contained in a tombstone of the same person.
- **No chat instruction writes memory.** "莱克记住 …" ("Lucky, remember …") from any member, maintainers included, is a message the consolidator may weigh but never obeys; it never records dictated rules of behaviour, forms of address or persona changes. `SELF.md` is the bot's own judgement plus hand edits. Memory grants no permissions: maintainers still come only from `maintainers`.
- **Injection.** The late-binding prompt (after the chatlog, so the cached prefix is unchanged) gets `SELF.md` plus the cards of the newest `recentSpeakers` human senders among the last `lookbackMessages` message segments, the newest sender's card first and marked `current="true"`, within `injectionMaxChars` (4000, equal shares with redistribution; newest entries kept, evidence aliases stripped) and `selfInjectionChars`. The probe gets `SELF.md` only. The snapshot is read once per wake-up before the probe (`loadMemorySnapshot`), and an unreadable directory degrades to no notes. `inject: false` is shadow mode: cards are written, nothing is injected, and the system-prompt "Your notes" paragraph is not rendered.
- **Config.** `memoryDir` (global) and `chats.<id>.memory` (`enabled`, `inject`, `model` → `compaction.model` → `primary.model`, `triggerMessages`, `maxWindowMessages`, `cardMaxChars`, `selfMaxChars`, `hearsayMaxEntries`, `hearsayMaxChars`, `injectionMaxChars`, `selfInjectionChars`, `lookbackMessages`, `recentSpeakers`, `doNotReadd`); `injectionMaxChars / recentSpeakers >= cardMaxChars / 2` and the other cross-field rules are checked on the merged chat config. Real-model and live Feishu behaviour are unverified.

### Consistency Above Availability

Enabled media transforms are blocking. A per-chat queue may transform later events speculatively, but only a contiguous ready prefix commits. A failed head retries indefinitely and blocks the session; partially transformed events never enter Adaptation.

### TDLib Resolution

Runtime resolves `vendor/libtdjson.so` first and falls back to `prebuilt-tdlib`. `types/tdlib-types.d.ts` is generated and gitignored. `pnpm tdlib:build` builds TDLib master, applies `scripts/tdlib-patches/*.patch`, and regenerates types. `postinstall` runs `pnpm tdlib:types`.

### Telegram Clients And Ingress

Bot and userbot are both tdl clients. With a configured userbot, it exclusively owns message/edit/delete/typing ingress; otherwise the bot provides limited ingress. Outbound sends always use the bot and wait for TDLib's terminal `updateMessageSendSucceeded`/`updateMessageSendFailed` before returning: TDLib resolves `sendMessage` with a per-dialog yet-unsent id while the upload and server confirmation continue asynchronously, so temp files backing `inputFileLocal` must live until that confirmation and the final server message id is only known there. There is no confirmation timeout — large uploads and FLOOD_WAIT retries keep the message pending for unbounded time while still making progress; pending sends are aborted only on client stop. Downloads prefer userbot and fall back to bot, keyed by `(chatId, messageId)` rather than persisted TDLib-local file IDs.

`TelegramManager` owns clients, the ordered ingress queue, and blocking transforms. Metadata resolution and media work run inside that queue after timestamps are captured. `live-handlers.ts` owns Telegram update side effects. `src/event-sink.ts` centralizes canonical persistence/publication. Commit and publication phases are idempotent so failures retry without advancing the queue cursor or duplicating events. `driver-hooks.ts` owns send/react/download and synthetic self-events. `post-startup.ts` owns historical media backfills.

Configured chats are the in-memory residency whitelist. Telegram archives unconfigured chats but does not project them. Feishu drops private chats and unconfigured groups without archiving. Feishu uses action-specific `events.dedup_key` values and a `(chat_id, dedup_key)` unique index; only configured groups are accepted. Feishu credentials (`feishu.appId`, `appSecret`, `domain`) live in the git-ignored `config.yaml` like the Telegram token and model keys, and are never copied to process.env. This is not a sandbox: a host Bash tool can still read local files, so do not enable it against real group input before isolating its filesystem.

### Spam Moderation

`ban_spammer(message_id, reason)` is chat-scoped and opt-in through `tools.banSpammer: true` (default false). The backend enforces the enabled-chat set. Group policy reaches both probe and primary through chat `systemFiles` alongside identity files. Deployment-local group policies can identify eligible accounts through sufficient conversational history showing exclusively one-off solicitation. Genuine questions, feedback, and ordinary exchanges establish normal participation. For normal members discussing topics outside the bot's permitted scope, the bot remains silent on that topic and leaves member conduct to human administrators. Archived names and messages serve as internal reference examples interpreted in context. The service derives the target from a persisted message author, verifies bot permissions and membership, and authorizes eligible members with fewer than 10 distinct observed message IDs. The archive count retains deleted messages, deduplicates edits, and survives compaction and rejoining; its scope is observed speech history. Eligibility is independent of join age.

Moderation uses the bot account for permanent bans and deletion of known accessible messages permitted within Telegram's 48-hour window. `src/telegram/moderation.ts` checks current state and performs each requested action; `moderation-api.ts` owns TDLib calls; `src/db/moderation.ts` queries the existing event archive. The existing tool call/result history records evidence ID, private reason, target UID, and actual outcomes. Each invocation freshly checks membership, evidence, and message count, then returns deletion results for that invocation. Confirmed removals enter Pipeline as canonical delete events with Driver notification disabled.

After a confirmed ban, the tool result supplies an exact announcement with a `tg://user?id=...` link labeled "spam 账号" ("spam account"). Primary calls `send_message` with exactly one argument, `text`, containing that announcement. Names, usernames, profile text, spam content, media, and audit reasoning stay in the private assessment. Partial cleanup receives its own factual announcement. The tool always requires follow-up. The group file directs probe activation for eligible cleanup and its notice. There is no longer a mandatory-send fallback, and `ban_spammer` counts against the primary turn budget, so the announcement depends on primary sending it within the budget (the wrap-up step keeps `send_message` available; a deadline close does not).

### Synthetic Self-Events

Every successful bot send creates a canonical `isSelfSent=true` event carrying the final server message id, persists it, and publishes it to Pipeline without waking Driver. Userbot echo deduplication matches on that message id and replaces the synthetic payload with authoritative Telegram content while preserving `isSelfSent` and the original local ordering timestamp. This closes the probe race without making final context arrival-order dependent.

### Telegram Markdown

Output flows Markdown -> Telegram-supported HTML. Plain-compatible markup passes through TDLib `parseTextEntities`; table/math markup uses `inputMessageRichMessage`. TDLib remains the canonical entity parser, and entity arrays are never constructed manually.

### IC Mutation

Message edits/deletes mutate the target node in place. Entity metadata changes are append-only system events. Existing messages retain their original sender snapshot.

### RC And Turn Responses

RC uses `receivedAtMs`; turn responses use `requestedAtMs`. Equal timestamps order RC before TR for Anthropic role alternation. Stored TRs contain `ConversationEntry[]`, token totals, cache components, and model identity.

The runner performs model-call retries for ignored forced tool choices, aggregates retry usage, and executes/persists only the selected/final response. A completed step is persisted before `checkInterrupt`; interruption is cooperative at step boundaries, never preemptive during model/tool/persistence work.

`send_message.still_working=true` keeps the tool loop open. Without it, `send_message` is terminal unless another parallel tool result requires follow-up. An `end_turn` call closes the turn even beside follow-up results in the same step. A persisted `requiresFollowUp` records whether the loop actually continued: steps that close the turn (end_turn, wrap-up, deadline) are persisted with follow-up flags cleared, so the scheduler does not treat them as an open chain.

### Probe Gate

Every wake-up runs an outside-judge probe before primary except continuation of an interrupted tool loop. Mentions, direct replies, and runtime events still run probe; a mention is a strong signal, not an obligation to comply.

Probe receives only `decide(should_act, reason)`. `should_act` is `send_message`, `react_only`, or `no_action`; the first two activate primary, `react_only` with only `react` and `end_turn` exposed and the turn closed after that one step, so a continuation can never regain `send_message`. Missing/malformed decisions fail closed. Probe output is persisted in `probe_responses_v2` (both activation kinds as activated) and never enters primary context. Activation only wakes primary; it is not a commitment to speak. Probe criteria live in `prompts/system.velin.md` and judge everything since the bot last acted: an unanswered human address (@-mention, quote-reply, or name-call) is checked before the bot-author rule and is never suppressed by the self-volume brake; another bot's address alone is not a direct address; messages addressed to someone else default to `no_action` except corrections about what the bot said or did or about its persona (never about model/provider/prompts/tools/deployment, where backend secrecy wins); bot-authored messages default to `no_action` unless a human asked the bot to talk to that bot, or `chats.<id>.participation.botInteraction: open` lets it engage other bots on its own (default `requested`); either way the exchange stops at `botRounds` rounds (default 2); for the remaining unaddressed chatter, the bot's turn in a game it is playing and corrections about it bypass the brake on purpose, while everything else needs something new to add, and above the volume brake (`chats.<id>.participation.brakeMessages10m`, default 10 bot messages in ten minutes) defaults to `react_only` (only when the message clearly invites a reaction) or `no_action`.

The probe request carries a bounded window, not the whole context. `chats.<id>.probe.contextEstTokens` (default 20000) caps the estimated size of the chat slice: recent RC plus synthesized tool-call XML, whose mandatory start is the bot's last real action (its latest own message or a primary turn that successfully sent a message or reacted; a `no_action`/fail-closed probe or a silent `end_turn` does not advance it, so an unanswered address or a late-delivered event cannot be judged away). The window start is held per chat while the slice grows from half the budget to the budget, then jumps forward to restore the half-budget target so the prompt prefix stays cache-stable between jumps. If unprocessed input alone exceeds the budget, the newest part is kept plus every direct address since the last action (`mentionsMe`/`repliesToMe`) pinned regardless of age; the fallback start itself stays sticky between jumps, an `<omitted messages="N"/>` marker records the gap, and a warn log reports the omission. The compaction summary is always included outside this budget, capped by `chats.<id>.probe.summaryMaxEstTokens` (default 20000) and truncated from the end. Window selection never changes primary context.

### Participation And Turn Budget

Implemented: an activated primary may end with `end_turn` and no message (legitimate silence), or `react` then `end_turn` (reaction-only). There is no forced-send fallback and no silence tool. Primary still uses `forceToolChoice: 'any'`; `end_turn` is the silence route. A `react_only` probe activation runs primary with only `react` and `end_turn`; `send_message` and work tools are not exposed, and a hallucinated call is rejected as an unknown tool.

The bash gate (`src/driver/bash-gate.ts`) is decided once per wake-up when the tool set is built and stays fixed for every step of the turn. An interrupted continuation reads the chain's persisted decision (`shell_tools_exposed`, written on every step) instead of recomputing, so a maintainer message arriving mid-chain or during the probe gap cannot open it. A closed gate omits the tools, and a hallucinated call is rejected as an unknown tool.

Probe and primary late-binding prompts receive participation signals computed by `src/driver/participation-stats.ts` from the unfiltered rendered context: `recentSelfMessages10m`, `secondsSinceLastSelfMessage`, and `consecutiveBotExchanges` (consecutive bot-authored messages since the last non-bot one; zero unless another bot is in the streak). Another bot is identified by the rendered `bot="true"` attribute; the bot's own messages carry `myself="true"` instead.

`chats.<id>.participation` tunes how talkative the bot is per chat. `style` (`quiet` | `normal` | `lively`, default `normal`) picks the probe's bar for unaddressed chatter in the system prompt: `quiet` drops the "can add something new" step and keeps only game turns, corrections and invited reactions, `normal` targets roughly one message per four to six human messages, `lively` one per two to three. `brakeMessages10m` (default 10) is the soft self-volume brake in both prompts. `botRounds` (default 2) caps a human-requested bot-to-bot exchange at that many rounds (two consecutive bot messages per round) in the probe criteria and the primary bot-to-bot notice. `botInteraction` (`requested` | `open`, default `requested`) decides whether another bot's message, @-mention or reply can wake the bot without a human asking; the cap check comes first in both modes. `cooldownSec` and `maxPerHour` (default 0 = off) are opt-in hard limits evaluated before probe by `src/driver/participation-limit.ts` from the rendered context: inside a cooldown since the bot's last own message, or with `maxPerHour` own messages in the last hour, the bot may not speak up unprompted. An @-mention, a quote-reply or a runtime event since its last action bypasses the limit deterministically. A name-call cannot be detected without string matching, so under a reached limit the probe still runs, its late-binding prompt says only a direct address may wake the bot, and the driver refuses a `react_only` decision outright. The limits never apply to interrupted continuations or retries that reuse a probe activation.

The primary loop is bounded by `TurnBudget` (`src/driver/types.ts`, defaults `DEFAULT_TURN_BUDGET` in `turn-loop.ts`: 2 tool rounds, 4 work-tool calls, 15 s deadline, 2 s minimum per model call, 6 s wrap-up reserve):

- Rounds and work-tool calls accumulate across the loaded persisted interruption chain (`interruptedChainUsage`). Sends/reactions have a separate combined attempt cap (default 3); `end_turn` is exempt. Compaction can truncate the history used for accounting; this limitation remains to be addressed.
- Over-budget work calls in a parallel step receive a not-executed error result; earlier calls run.
- When counts are exhausted, or less than `wrapUpReserveMs` of the deadline is left (0 disables it; otherwise it must lie between `minModelCallMs` and `deadlineMs`), one wrap-up step exposes only participation tools; its follow-ups are cleared, closing the chain. The time trigger gives a turn that spent its time on tools one chance to answer; only a step that leaves less than `minModelCallMs` still closes silently. The next wake-up runs probe with a fresh budget.
- The deadline is per wake-up execution, not the whole interruption chain, and starts when primary starts: probe never consumes it. Probe has its own HTTP bound, `chats.<id>.probe.timeoutMs` (default `DEFAULT_PROBE_TIMEOUT_MS`, 15 s, in `turn-budget.ts`; the endpoint `timeoutSec` applies if lower), so a wake-up's worst-case latency is probe timeout plus primary deadline plus any in-flight tool. Primary model HTTP waits are capped by remaining time. Before every new side effect the runner checks expiry; already-running tools are not preempted and their results are persisted. Thus the deadline is not a hard timeout on an in-flight tool. Expired entry throws into the scheduler failed-context guard rather than spinning.
- Budget overrides live at `chats.<id>.primary.turnBudget`; merged configuration requires `deadlineMs > minModelCallMs`. A transiently failed wake-up is retried by the scheduler (see Scheduling); a model failure mid-chain leaves an open continuation that the retry, or the next context change, resumes without probe. Real-model and live Feishu behavior remain unverified.

### Scheduling

Each chat owns an alien-signals scheduler. The trigger sender's later messages extend the initial delay; other senders do not. Typing extends the delay. `maxDelayMs` caps the window. Calls are serialized. New input during a tool loop is observed only after the current step is persisted; the continuation inherits the chain's round/call usage, and a closed chain gives the next input a fresh probe and budget. Scheduler cleanup does not preempt a running turn.

Failures: `index.ts` classifies a thrown wake-up with `isTransientModelError` (`transient-error.ts`: transport timeouts, undici `fetch failed`/`terminated`, socket/timeout error codes anywhere in the `cause` chain, HTTP 408/409/425/429/5xx). A primary model call whose timeout the runner shortened to the remaining turn deadline is rethrown as `Turn deadline reached during model step N`, which is permanent; a provider timeout shorter than the remaining deadline stays transient. A transient failure schedules a retry on the same context after `DEFAULT_RETRY_DELAYS_MS` (5 s, then 20 s), regardless of whether probe already advanced the watermark. If probe already activated that context, the retry reuses the activation and its reason and goes straight to primary; probe reruns only when probe itself failed. If primary had persisted an open step, the retry is an ordinary continuation (no probe, chain budget carried over). Exhausted retries and every other error set `failedContext`, so that context is not rerun until it changes. Retry liveness is decided by unprocessed external input, not RC identity: the retry records the latest external `receivedAtMs` of the failed context and stays live (running against the current RC, with any carried probe activation) across compaction, edits, deletes, metadata and self-events. A newer external segment supersedes it (debug-logged), and the normal debounced wake-up runs with a fresh retry count. Typing does not postpone a live retry; dispose cancels it. At defaults one attempt takes at most ~30 s (15 s probe timeout + 15 s primary deadline, plus any in-flight tool), so a wake-up is abandoned after ~115 s in the worst case.

### Compaction

Compaction is an independent per-chat controller, not a turn feature or TR. Raw RC + TR content after the cursor, excluding the existing summary, triggers at `maxContextEstTokens`. The retained window targets `workingWindowEstTokens`. Summaries are append-only rows in `compactions`; updating the signal applies the new Pipeline cursor.

The estimate counts message-level reasoning (`reasoning_content` and aliases) and block-level reasoning parts; ignoring the former undercounted the live primary turn by about 25% and would have delayed compaction. The blended rate stays at ~2 chars/token, calibrated on live DeepSeek requests (2026-10-17: primary ~532K text/reasoning chars → 262,248 input tokens; probe 416K chars → 205,322); opaque reasoning (Anthropic signatures, OpenAI `encrypted_content`) counts at ~4 chars/token. The compaction input cap is `maxContextEstTokens` plus 20K headroom, and the existing summary is subtracted from that cap (protected from trimming, not outside it): only the oldest raw entries are trimmed, and when the window would still exceed the cap the cursor advances only to the content actually summarized, leaving the rest for the next compaction. A failed compaction is latched with exponential backoff (5 min doubling up to 1 h) and the latch resets after a success.

### Provider Boundaries

`src/llm/call.ts` is the common non-streaming call boundary. It enforces `maxImagesAllowed` on every request, converts IR through `src/unified-api/`, normalizes usage, and writes debug request/response JSON under `/tmp/cahciua/`.

Reasoning survives replay only when the stored model identity is compatible, and only for the newest `chats.<id>.primary.reasoningReplayTurns` turn responses (default 3) plus the current interrupted chain, whose thinking blocks Anthropic requires beside pending `tool_use`. Older reasoning is stripped when the request is built; persisted turn responses stay unchanged. Tool call IDs remain provider-native in storage and are sanitized only for wire formats that require it.

Token semantics are uniform:

- `inputTokens` is total billable input, including Anthropic cache reads/writes.
- `cacheReadTokens` is the cached-input component.
- `cacheWriteTokens` is Anthropic cache creation; other formats report zero.

### Media

`src/media/` owns all provider/platform-neutral processing. Telegram only supplies bytes and metadata.

- Passive image alt text: thumbnail WebP hash is the cache key; model input is JPEG (quality 80, alpha flattened onto white) <=512px; explicit `read_image(detail="high")` may use 1024px. Every image part is re-encoded as JPEG at the wire boundary (`sharpToEncoded`), because base64 PNGs kept in context were re-sent on every wake-up.
- Animations/stickers: file SHA-256 is the key; frames are count-based/equidistant; gzip magic identifies TGS; files over 20 MB fail.
- Custom emoji: cache key is `emoji:<id>`; the bot client supplies media bytes.

Alt text is read transiently from `image_alt_texts` and is not persisted in event JSON. Resolver model, concurrency, and frame limits are selected per chat; cache records remain content-addressed and shared. Content-aware frame selection remains deferred in `docs/content-aware-frame-selection.md`.

### Security And Diagnostics

Identity is encoded in XML attributes, never user-controlled inline labels. `registerHttpSecret()` redacts credentials in HTTP errors. Full request dumps under `/tmp/cahciua/` are intentional for this research deployment.

## Conventions

- Functional factories, `const`, arrow functions. Classes only for library contracts or Error subclasses.
- Strict types; avoid `any`; use `unknown` and narrowing. `import type` is enforced.
- Kebab-case files, relative imports, current ES syntax.
- `@guiiai/logg` only; `console.log` is for CLI copy-paste output.
- Comments record non-obvious decisions, constraints, and evidence. Do not narrate code.
- Let errors propagate. Do not silently catch or invent defaults for invalid data.
- Style: 2 spaces, single quotes, semicolons, multiline trailing commas, 1TBS, LF.

## Testing And Dependencies

Vitest tests live next to source as `*.test.ts`. Add regression tests for bugs and characterization tests before behavior-preserving structural changes. Driver, startup/DI, persistence, and Telegram integration are high-risk boundaries.

Use `pnpm add [-D]`; never hand-edit dependency manifests. For runtime changes, run relevant tests and, where dependencies are available, `pnpm typecheck`, `pnpm lint`, `pnpm test:run`, and `pnpm build`. Avoid unrelated auto-formatting. Documentation-only changes need diff/link checks, not a full build. Report checks not run; ask before installing missing tools.

Generated/local directories (`data/`, `.tdlib-build/`, `types/`, `dist/`) are excluded from lint.

## Data Migration

Code handles only the current data shape. Existing data changes require a new Drizzle migration; never add runtime legacy fallbacks.

## Commits

Conventional Commits. Keep changes focused and update architectural docs in the same commit. **Never commit or push without explicit human instruction.**

Single-thread mode (one agent working directly with the maintainer, no parallel delegated branches): once a commit is authorized, push it straight to `main`; do not open a pull request against your own work. Delegated or parallel work still lands through its own branch and a reviewed pull request.

### Commit Identity

- For original work, use the human contributor's configured Git `user.name` and `user.email`, unless the user explicitly specifies another identity.
- Before committing, verify the effective author and committer identity. Do not silently override them.
- Never infer identity from the repository owner, remote URL, PR target, historical commits, or names mentioned in this guide.
- For ports, preserve source authorship as described below; the committer remains the current human contributor.
- Preserve accurate human attribution and omit AI co-author trailers.

## Upstream And Ports

`origin` is the public LuckyBot repository (`aronnaxlin/LuckyBot`, MIT); `upstream` is `Menci/Cahciua`. There is no configured Edelweiss downstream workflow. Do not create remotes, synchronize repositories, or open upstream PRs unless requested.

Preserve source authorship and reference source commits when porting changes. Original work follows the Commit Identity rules above. Evaluate ports against LuckyBot's goals rather than inherited upstream feature bans; do not import another deployment's persona, secrets, or infrastructure configuration. Keep unrelated changes out of the same commit.

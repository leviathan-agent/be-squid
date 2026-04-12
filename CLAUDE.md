# CLAUDE.md

This file provides guidance to Claude Code (claude.ai/code) when working with code in this repository.

## Project Overview

This is the **Leviathan News (LN)** workspace — a crypto/DeFi news curation system with two main components:

1. **`ln-agent.py`** — Automated news agent. Monitors Telegram channels (configured via `CHANNELS` env var), evaluates newsworthiness via Claude CLI (Codex fallback), deduplicates, crafts headlines, posts via LN API. Also votes and writes TL;DR comments.

2. **`benthic-bot.py`** — Telegram chat bot (PM2 name `benthic-bot`) sharing brain/identity with ln-agent. Responds in groups and operator DMs. Features: per-chat memory isolation, tiered operator auth, [GROUP] directive routing, agent-chat API polling, message debouncing, media analysis, persistent memory, self-awareness tracking.

3. **`skills/leviathan-headlines/`** — Claude Code plugin skill for manual headline crafting and review following LN editorial standards.

## Architecture: ln-agent.py

Single-file Python agent running in a continuous loop (`run_loop`) with a flat 1-hour sleep after each completed cycle. Each cycle has five phases, with Phase 3 running articles in parallel threads:

1. **Read** — Connect to Telegram via Telethon, fetch new messages from `CHANNELS` list using cursor-based pagination (stored in SQLite). Channel usernames are resolved to numeric IDs and cached to avoid flood waits.
2. **Evaluate** — Batch all messages to the provider layer for newsworthiness scoring and story-level deduplication. Claude CLI (`claude -p - --effort max --allowedTools <whitelist>`) is primary; Codex CLI (`codex exec`) is fallback when Claude errors or hits limits. The model is instructed to use WebSearch/WebFetch/twitter-explorer to verify stories and find primary sources. Output is strict JSON.
3. **Post** — For each newsworthy item: check DB + Bot HQ for duplicates, verify freshness, resolve URL + craft headline + write TL;DR in a single Opus call (`resolve_craft_headline_tldr()`), submit via LN API (`/api/v1/news/post`), auto-upvote, add TL;DR comment.
4. **Vote/Comment** — Fetch recent approved articles from LN API, evaluate quality via the provider layer, vote up/down, write analysis comments on uncommented articles. Also votes on other users' comments (yaps).
5. **Reply Detection** — Separate pass over last 20 articles we've commented on (regardless of age). Detects unreplied responses to our comments via `walk_replies_and_respond()`, crafts replies with prompt injection defense + sentinel verification. Skips articles already processed in Phase 4.

### Key Classes
- **`AgentDB`** — SQLite wrapper (WAL mode) with tables: `channel_cursors`, `channel_ids`, `evaluated_messages`, `posted_articles`, `commented_articles`, `voted_articles`, `voted_yaps`, `replied_yaps`, `runs`
- **`LNClient`** — LN API client with wallet-based auth (nonce → sign → verify → JWT). Endpoints: `/news/post`, `/news/{id}/vote`, `/news/{id}/post_yap`, `/news/{id}/list_yaps`

### AI Evaluation Functions
All AI calls go through `llm_ask()`, a provider wrapper with two tiers:
- **Creative tier** (Opus, max effort, full tools, soul prompt): headlines, TL;DR, analysis, replies
- **Classification tier** (Sonnet, low effort, no tools, no soul): votes, freshness, dup checks, reply worthiness

`llm_ask()` params: `claude_model`, `claude_effort`, `skip_soul`, `allowed_tools`. Provider order configurable via `PROVIDER_ORDER` env var (default: `claude,codex,opencode`). OpenCode dormant unless `OPENCODE_MODEL` is set. `"__none__"` sentinel = no tools.

Key functions:
- `evaluate_and_deduplicate()` — batch evaluation, returns JSON array
- `batch_evaluate_articles()` / `batch_evaluate_comments()` — JSON batch eval for Phase 4 (reduces LLM calls)
- `_extract_json_array()` — 3-pass JSON extraction (fences, raw parse, bracket search)
- `_pre_filter_message()` — keyword pre-filter before LLM eval (skips obvious noise)
- `resolve_craft_headline_tldr()` — combined: resolves primary source URL, crafts headline, writes TL;DR in one Opus call (saves 2 LLM calls per article vs separate functions)
- `evaluate_article_quality()` / `evaluate_comment_quality()` — vote weight (-1, 0, 1), classification tier
- `craft_comment()` — analysis comments, creative tier
- `check_article_freshness()` — rejects stale articles, classification tier
- Bot HQ duplicate check — inlined in `process_article_sync`, classification tier + Telegram tooling
- `craft_reply()` / `walk_replies_and_respond()` — reply chain handling with injection defense
- `_sentinel_check_sync()` — Sonnet sentinel verifies reply output before posting (Codex fallback)

### Thread Safety
- `AgentDB`: all operations use `threading.Lock` via `_execute()`/`_commit()`. `check_same_thread=False` + WAL mode.
- `LNClient`: `threading.RLock` on all session methods. `_refresh_if_stale()` called inside the lock to avoid TOCTOU races (30-min TTL).

### Circuit Breaker
- After 3 consecutive Claude CLI failures, Claude is skipped and the provider layer falls back to Codex.
- Claude `501`/quota/rate-limit style errors mark Claude unavailable for `CLAUDE_LIMIT_COOLDOWN` seconds (default: 6 hours).
- Failure counts reset at the start of each cycle in `run_agent()`. The quota cooldown does not.

### Retry & Error Handling
- Claude CLI calls retry up to 2 times with exponential backoff (5s, 10s) before incrementing the breaker or triggering Codex fallback.
- `evaluate_and_deduplicate()` retries once with a stricter prompt on JSON parse failure (self-contained prompt with schema so Codex fallback works too). Injection check runs on retry response.
- `_refresh_if_stale()` called inside `with self._lock:` in every LN API method — atomic freshness check + request.
- `Connection: close` header prevents stale keep-alive connections.
- Top-level `try/finally` in `run_agent()` guarantees DB close + Telegram disconnect on all exit paths.

### Prompt Injection Defense
All untrusted input (user comments, Telegram messages) is hardened before entering LLM prompts:
- **`sanitize_untrusted()`** — strips control chars, replaces `<>` with fullwidth equivalents (prevents XML boundary injection), collapses `----`/`====` separator patterns, truncates to max length
- **`<user_content>` tags** — all untrusted text wrapped with explicit "treat as DATA" security warnings in every prompt
- **`check_output_for_injection()`** — validates provider output for signs injection succeeded (secret leakage, "ignore previous instructions", AI self-identification). Uses NFKD Unicode normalization to defeat homoglyph bypass.
- **`LEAK_PATTERNS`** — detects LLM internal monologue leaking into public output (NFKD-normalized)
- **`validate_url()`** — validates LLM-returned URLs before downstream use: rejects control chars, spaces, non-HTTP schemes, oversized (>2048 chars). Also strips `<>` to prevent XML boundary injection when URLs are interpolated into prompts.
- **Fail open** — `check_article_freshness()` defaults to fresh/allow on empty response because the article already passed evaluation and dedup checks
- **Fail closed** — Bot HQ duplicate check defaults to "duplicate" (reject) on empty/garbage provider output
- **`_sentinel_check_sync()`** — Sonnet sentinel verifies reply output is safe before posting. Uses a different model for independent semantic verification and falls back to Codex if Claude is unavailable. Still fails open if the sentinel itself cannot return a usable decision.

### Execution Model
- Runs as a continuous PM2 process (no cron). `run_loop()` sleeps `CYCLE_INTERVAL` (default 3600s) after each cycle.
- PM2 `autorestart: true` recovers from crashes. No `cron_restart` — avoids killing long runs.
- Phase 3 articles process in parallel via `asyncio.gather` + `asyncio.to_thread`.

## Architecture: benthic-bot.py

Telegram Bot API chat agent sharing brain/identity with ln-agent. Uses `getUpdates` long polling.

### Poll Loop (3-phase)
1. **Collect** — `getUpdates` with long polling, collect messages per-sender
2. **Merge** — Debounce consecutive rapid messages from same sender (saves tokens, coherent context)
3. **Process** — For each merged message: check response criteria, generate response, send

### Key Subsystems
- **Per-chat memory isolation** — `recent_by_chat` dict keyed by chat ID. Operators in DMs get merged cross-group context with `[GroupName]` headers; non-private stays isolated.
- **Operator tiered auth** — `OPERATOR_IDS` (Telegram user IDs, unforgeable). Operators get `TOOLS_OPERATOR` (path-restricted Bash for diagnostics). Non-operators get `TOOLS_DEFAULT` (read-only research).
- **[GROUP] directive** — Operators in DMs prefix with `[GROUP]` or `[GROUP:topic_id]` to route messages to agents group. Multi-command splits on newlines, sends each as separate message.
- **Agent-chat API poll** — `_poll_agent_chat()` fetches from LN's public chat history API every 60s. Content-based dedup (`_content_key()`) prevents double-responding across Telegram/API paths.
- **Media support** — PIL re-encode for images (strips EXIF/metadata, MAX_IMAGE_PIXELS=25M). PDFs blocked. Text files sanitized.
- **Persistent memory** — `notes` SQLite table with `[REMEMBER:category]`/`[UPDATE:id]`/`[FORGET:id]` directives. Categories: goal, person, task, stance, learning, note. Operator-only writes (non-operator directives stripped without execution), auto-prunes at 200. Bot instructed to update existing notes rather than creating duplicates.
- **Self-awareness** — `own_actions` table tracks all bot actions (bets, messages, replies).
- **Autonomous trading** — Periodic market evaluation via `_check_markets()` every `MARKET_CHECK_INTERVAL` (default 1800s/30min). Fetches live market data from LN API (`_fetch_market_data()`), feeds to Sonnet/low with cached positions (`_get_cached_positions()`), executes trades via API (`_try_api_command()`). Persistent market check timestamp (`_MARKET_CHECK_FILE`) survives restarts. Also trades reactively during normal message processing — responses are split via `_split_bot_commands()` and trade commands routed through LN API.
- **API-routed trades** — `_try_api_command()` intercepts BUY/SELL/POSITION/MARKETS commands and executes via LN REST API instead of Telegram messages. `_split_bot_commands()` separates mixed analysis+trade responses so each command routes independently.
- **Two-pass pre-screen** — Group messages (non-direct) go through Sonnet/low pre-screen (~30 tokens) before expensive DB queries + Opus response. ~70% of messages filtered as SKIP, saving ~9,500 tokens per skipped message. Bypass keywords for market-relevant content. Reply-to-other detection reduces false positives in threaded conversations.
- **Topic-aware context** — `chat_history` table includes `topic_id` column. `get_chat_history()` filters by both `chat_id` and `topic_id` in forum groups to prevent cross-topic context bleeding. Topic label injected into prompt so Benthic stays focused.
- **Knowledge base** — `knowledge` SQLite table with 15 platform reference topics (prediction markets, SQUID economy, tipping, article system, etc.). Loaded on-demand via word-boundary keyword matching against message + recent conversation context. Capped at `MAX_KNOWLEDGE_TOPICS=5` per prompt. Topics seeded at startup via `seed_knowledge()`.
- **Tiered LLM calls** — `llm_ask()` accepts `model` and `effort` params. Pre-screen and `_check_markets` use `model="sonnet", effort="low"`. Full responses use default Opus/max.
- **LLM provider layer** — Same Claude/Codex fallback with circuit breaker as ln-agent.py.
- **Agent-chat relay** — `AgentChatRelay` class posts bot messages to LN's agent-chat API for history visibility.
- **Docker sandbox** — Ephemeral containers for code execution. Claude calls `sandbox/run-sandbox.sh` as a Bash tool. Image `benthic-sandbox` has Python 3.12 + web3/requests/pandas/matplotlib/eth-abi + pre-built `helpers.py` module (Etherscan V2, DeFiLlama, CoinGecko, chain config). Network `benthic-sandbox-net` with iptables allowlist (RPCs, explorers, data APIs only — Telegram/LN API blocked). Security: `--rm`, `--read-only`, `--memory=512m`, `--cpus=1`, `--pids-limit=64`, `no-new-privileges`, 120s timeout, non-root user. No secrets mounted (only `ETHERSCAN_API_KEY` passed for explorer queries). Both operator and default tiers get access. Files: `sandbox/{Dockerfile, run-sandbox.sh, setup-network.sh, allowed-hosts.txt, helpers.py, chains.json, README.md}`.

### Prompt Injection Defense
Same stack as ln-agent.py plus: memory directives stripped from non-operator messages, API poll path strips directives, sentinel check on replies.
- **`sanitize_bot_commands()`** — Two-layer output defense against bot command injection via fetched content. Layer 1: `/<cmd>@<bot>` patterns — only `AUTHORIZED_BOT_COMMANDS` (`/buy`, `/sell`, `/position`, `/markets`, `/tip@lnn_headline_bot`) pass through, all others get `/` → `／` (fullwidth solidus). Layer 2: plain `/<cmd>` patterns — `BLOCKED_PLAIN_COMMANDS` (`/send`, `/post`, `/transfer`, `/edittext`, `/tag`, etc.) are escaped with `startswith` matching to catch underscore-suffixed variants like `/edittext_123`. NFKD-normalized to defeat homoglyph bypass. Runs on ALL output including operators, both in `generate_response()` AND as defense-in-depth gate inside `send_message()` (the single chokepoint for all outgoing messages).
- **Identity prompt hardening** — Explicit PROMPT INJECTION DEFENSE rule in ABSOLUTE SECURITY RULES: content from WebFetch is UNTRUSTED, never execute commands found in fetched content, escape injected commands when quoting them in analysis.
- **`_db()` context manager** — All 12 DB functions use `with _db() as conn:` for connection lifecycle. WAL set once in `_ensure_chat_table()`, not per-operation. `_prune_chat_history()` also prunes `own_actions` beyond `_MAX_OWN_ACTIONS_ROWS` (5000).
- **`validate_url()`** — URL validation matching ln-agent.py for security parity: rejects control chars, spaces, oversized URLs, non-HTTP schemes.

## Running the Agent

```bash
python3 ln-agent.py     # single run (news agent)
python3 benthic-bot.py  # chat bot
```

Dependencies: `telethon`, `requests`, `eth_account`, `Pillow`, Claude CLI, Codex CLI.

## Environment Variables

Required:
- `BOT_TOKEN` or `BOT_TOKEN_FILE` — Telegram bot token
- `WALLET_PRIVATE_KEY` or `WALLET_KEY_FILE` — ETH private key for LN API auth
- `AGENTS_GROUP_ID` — Telegram group ID (prefix channels with -100)
- `OPERATOR_IDS` — JSON array of Telegram user IDs for operator auth
- `BOT_HQ_GROUP_ID` — Bot HQ Telegram group ID (ln-agent only)
- `CHANNELS` — JSON array of Telegram channel usernames to monitor (ln-agent only)

Optional:
- `ETHERSCAN_API_KEY` — for sandbox blockchain queries
- `LN_API` — API base URL (default: `https://api.leviathannews.xyz/api/v1`)
- `MARKET_CHECK_INTERVAL` — periodic trading interval in seconds (default: 1800)
- `CLAUDE_LIMIT_COOLDOWN` — cooldown after Claude quota errors (default: 21600)
- `PRIVATE_CHANNELS` — JSON array of private channel names
- `ALLOWED_GROUPS` — JSON array of additional group IDs to respond in
- `AUTO_DOWNVOTE_USERS` — comma-separated usernames for auto-downvote

## Sandbox

```bash
# Build sandbox image
docker build -t benthic-sandbox sandbox/

# Set up network allowlist
sudo bash sandbox/setup-network.sh

# Test sandbox
ETHERSCAN_API_KEY=<key> sandbox/run-sandbox.sh "from helpers import *; print(list_chains())"
```

## Headline Validation

```bash
./skills/leviathan-headlines/scripts/validate-headline.sh "Your headline here"
```

Checks: character count (75-150), trailing period, sentence case, article usage, first person, @ symbols, passive voice, multiple URLs, semicolon+and, mainnet capitalization. Exit 0 = pass, exit 1 = fail, exit 2 = no input.

## LN API

- Base: `https://api.leviathannews.xyz/api/v1`
- Auth: wallet nonce/sign/verify flow → JWT cookie
- Bot HQ Telegram group: `BOT_HQ_GROUP_ID` env var (ground truth for duplicate checking, not LN API)

## Important Conventions

- The agent posts via LN API (wallet auth), **never** via Telegram bot commands
- Bot HQ is the ground truth for duplicate detection — the LN API may show auto-posted articles from Tsunami that weren't actually approved
- `@LeviathanTsunami` articles are always submitted even if LN API says they exist (Tsunami auto-posts don't reach main feed via Bot HQ)
- `AUTO_DOWNVOTE_USERS` (env var, comma-separated) — exact-match on username, always auto-downvoted, no Claude evaluation
- Channel numeric IDs are cached in SQLite to avoid Telegram `ResolveUsernameRequest` flood waits
- Claude CLI uses `--allowedTools` whitelist (WebSearch, WebFetch, Read, Grep, Glob, + read-only Bash patterns for telegram_client.py, twitter_fetch.py, validate-headline.sh). No `Skill` — removed after security audit (Skill gave unrestricted access to telegram-explorer send capability). Telegram client restricted to read-only subcommands (messages, search-global, dialogs, info, topics, pinned).
- Codex fallback runs with `codex exec --ephemeral --dangerously-bypass-approvals-and-sandbox`
- Log rotation: 10MB max, 5 backups. LLM timeout: 1 hour per call.
- All HTTP calls to LN API have 5-min timeout
- LN API reply threading uses URL path (`/news/{yap_id}/post_yap`) to set parent — NOT `parent_id` body param
- `check_article_freshness()` fails open on empty response: unknown/empty = allow, explicit `stale` = reject
- User-generated content (comments, display names) is always sanitized via `sanitize_untrusted()` before any LLM prompt
- WebFetch content is treated as UNTRUSTED in all craft functions (craft_headline, craft_tldr, craft_comment) — explicit security warnings in prompts prevent injected instructions from being followed

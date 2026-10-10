# LLM Gateway

The superglue **LLM gateway** is an optional HTTP server (`gateway` feature) that sits between your applications and upstream LLM providers. It exposes an OpenAI-compatible API with governance features inspired by [any-llm-gateway](https://github.com/mozilla-ai/any-llm):

- **Virtual API keys** with per-key model allowlists (stored in SQLite)
- **Master key** for admin operations
- **Users and budgets** with lazy auto-reset
- **Usage analytics** (tokens, billed or estimated cost, attribution)

## Quick start

Build and run with the gateway feature:

```bash
cargo build --features gateway --release

export GATEWAY_MASTER_KEY="your-secure-master-key"
export OPENAI_API_KEY="sk-..."

superglue gateway serve \
  --addr 127.0.0.1:8080 \
  --db ./superglue-gateway.db
```

## CLI management

Manage the gateway via a local SQLite file or a remote HTTPS admin API.

**Local** (default): reads/writes `--db` (default `./superglue-gateway.db`).

**Remote**: pass `--url` and `--master-key` (or env `SUPERGLUE_GATEWAY_URL` / `GATEWAY_MASTER_KEY`):

```bash
export SUPERGLUE_GATEWAY_URL=https://gateway.myharn.sh
export GATEWAY_MASTER_KEY=...

superglue gateway --url "$SUPERGLUE_GATEWAY_URL" user list
superglue gateway --url "$SUPERGLUE_GATEWAY_URL" key create --user-id alice --model 'openai:*'
```

All manage commands accept `--output pretty|json`. Remote mode uses the same subcommands as local mode.

```bash
# Budgets
superglue gateway budget create --max-budget 10 --duration-sec 2592000
superglue gateway budget create --max-budget 50 --duration-sec 2592000 --enforce false  # track-only
superglue gateway budget list

# Profiles (model defaults, optional budget, optional reasoning cap)
superglue gateway profile create --name default \
  --model 'openai:*' --model 'anthropic:*' \
  --budget-id <budget-id>
superglue gateway profile list
superglue gateway profile update --id <profile-id> --model 'openai:*' --enabled true
superglue gateway profile delete --id <profile-id>

# Users (assign a profile to copy its budget onto the user)
superglue gateway user create --user-id alice --alias Alice --profile-id <profile-id>
superglue gateway user list
superglue gateway user update --user-id alice --profile-id <profile-id>

# Virtual keys (model flag is repeatable; omit --model to inherit from the user's profile)
superglue gateway key create --user-id alice
superglue gateway key create --user-id alice --model openai:gpt-4o-mini --model anthropic:*
superglue gateway key list
superglue gateway key update --id <key-id> --active false
superglue gateway key delete --id <key-id>

# Usage
superglue gateway usage list --user-id alice --limit 50
superglue gateway usage list --output json
superglue gateway usage prune-zero

# Models (allowed patterns for a key; master key shows unrestricted *)
superglue gateway model list
superglue gateway model list --key sgw-...
superglue gateway --url "$SUPERGLUE_GATEWAY_URL" model list
```

A **profile** stores allowed model patterns, an optional budget, and an optional
`max_reasoning_effort`. User budgets come only from the assigned profile —
there is no direct per-user budget assignment. Assigning a profile copies the
profile budget onto that user; clearing or deleting the profile clears the
user budget. Creating a key with no `--model` flags copies the user's enabled
profile models (and reasoning cap) onto the key. Existing keys keep their own
allowlist until you update them.

Key creation prints the plaintext secret **once** — store it immediately.

## Web admin

Build the gateway admin UI before building the gateway binary:

```bash
cd gateway-admin
npm ci
npm run build
cd ..
cargo build --features gateway --release
```

Open `https://gateway.example.com/admin` and sign in with `GATEWAY_MASTER_KEY`.
The key stays in the browser session and is sent to the gateway admin API.

## Authentication

Clients authenticate with either header (`X-Superglue-Key` takes precedence):

```
Authorization: Bearer <key>
X-Superglue-Key: Bearer <key>
```

- **Master key** — full admin access; completion requests must include `"user": "<user_id>"` in the JSON body
- **Virtual keys** — scoped to allowed models; usage is attributed to the key's linked user automatically

## Admin setup (HTTP API)

Alternatively, use the HTTP admin API while the server is running:

```bash
# Create a budget ($10/month, enforced)
curl -X POST http://localhost:8080/v1/budgets \
  -H "X-Superglue-Key: Bearer $GATEWAY_MASTER_KEY" \
  -H "Content-Type: application/json" \
  -d '{"max_budget": 10.0, "duration_sec": 2592000, "enforce": true}'

# Create a profile (models + budget defaults)
curl -X POST http://localhost:8080/v1/profiles \
  -H "X-Superglue-Key: Bearer $GATEWAY_MASTER_KEY" \
  -H "Content-Type: application/json" \
  -d '{"name":"default","allowed_models":["openai:*","anthropic:*"],"budget_id":"<budget-id>"}'

# Create a user with that profile (budget is copied from the profile)
curl -X POST http://localhost:8080/v1/users \
  -H "X-Superglue-Key: Bearer $GATEWAY_MASTER_KEY" \
  -H "Content-Type: application/json" \
  -d '{"user_id": "alice", "alias": "Alice", "profile_id": "<profile-id>"}'

# Create a virtual key (omit allowed_models to inherit from the user's profile)
curl -X POST http://localhost:8080/v1/keys \
  -H "X-Superglue-Key: Bearer $GATEWAY_MASTER_KEY" \
  -H "Content-Type: application/json" \
  -d '{"name": "alice-app", "user_id": "alice"}'
```

The plaintext key is returned **once** in the response. Store it securely.

## Model allowlist

Each virtual key requires at least one pattern in `allowed_models`:

| Pattern | Matches |
|---------|---------|
| `openai:gpt-4o-mini` | Exact model string |
| `openai:*` | Any OpenAI model |
| `*` | All models |

Keys with no allowlist rows are denied (explicit opt-in). The master key is unrestricted.

`GET /v1/models` returns allowed model patterns for scoped keys. For the master key (or `*` allowlist), it fetches and merges model ids from each configured upstream provider (`openai:…`, `anthropic:…`, etc.) via each provider's `/v1/models` API.

## Completions

```bash
curl -X POST http://localhost:8080/v1/chat/completions \
  -H "X-Superglue-Key: Bearer sgw-..." \
  -H "Content-Type: application/json" \
  -d '{
    "model": "openai:gpt-4o-mini",
    "messages": [{"role": "user", "content": "Hello!"}]
  }'
```

Models use the `provider:model` format (`openai:gpt-4o-mini`, `anthropic:claude-3-5-sonnet-20241022`, etc.).

Streaming is supported via `"stream": true`.

## Responses API

```bash
curl -X POST http://localhost:8080/v1/responses \
  -H "X-Superglue-Key: Bearer sgw-..." \
  -H "Content-Type: application/json" \
  -d '{
    "model": "openai:gpt-4o-mini",
    "input": "Hello!",
    "stream": false
  }'
```

Supports `openai`, `xai`, and `groq` via OpenAI-compatible `/v1/responses`, and `anthropic` via Messages translation. Streaming uses `"stream": true` (SSE).

## Budget enforcement

- **enforce=true** — reject requests when `spend >= max_budget` (HTTP 429)
- **enforce=false** — track spend but never reject (track-only mode)
- Budgets reset lazily per user when `next_budget_reset_at` passes

**v1 limitation:** there is no cost reservation. A single large request may push spend above the budget limit after the pre-check passes.

## Costing

Token counts are logged from provider responses. USD cost uses the static rates in [`src/costing/mod.rs`](../src/costing/mod.rs). Unknown models (most Anthropic/xAI/Groq models today) log `$0.00` cost — expand the pricing table for accurate analytics.

## Provider credentials

Upstream provider API keys are loaded from environment variables on the server (`OPENAI_API_KEY`, `ANTHROPIC_API_KEY`, `XAI_API_KEY`, `GROQ_API_KEY`, `OPENROUTER_API_KEY` or `OPENROUTER_GATEWAY_KEY`, `RUNINFRA_GATEWAY_KEY`, `VERCEL_GATEWAY_KEY`, `TYPESAFE_API_KEY`, `OPENAI_BASE_URL`, `TYPESAFE_BASE_URL`). Clients never see provider credentials.

## System One (TypeSafe)

TypeSafe is an evaluation API, not a chat model. Use `POST /v1/systemone` with `typesafe:jev-latest` (or a bare `jev-latest`). Do not send `typesafe:...` to `/v1/chat/completions` or `/v1/responses`.

```bash
curl -X POST http://localhost:8080/v1/systemone \
  -H "X-Superglue-Key: Bearer sgw-..." \
  -H "Content-Type: application/json" \
  -d '{
    "state": "Help! My payouts have been failing for 3 days.",
    "model": "typesafe:jev-latest",
    "questions": {
      "is_urgent": {
        "type": "noul",
        "instructions": "Does this convey urgency?"
      }
    }
  }'
```

Allowlist patterns use `typesafe:jev-latest` or `typesafe:*`. Token usage is recorded. Cost is `$0.00` until a TypeSafe rate exists.

## API reference

| Method | Path | Auth | Purpose |
|--------|------|------|---------|
| GET | `/health` | none | Liveness |
| GET | `/health/ready` | none | Readiness (DB ping) |
| POST | `/v1/chat/completions` | any key | Proxy completion |
| POST | `/v1/responses` | any key | Proxy Responses API (OpenAI-shaped; multi-provider) |
| POST | `/v1/systemone` | any key | Proxy TypeSafe System One evaluation |
| GET | `/v1/models` | any key | List allowed models |
| POST/GET | `/v1/keys` | master | Create/list virtual keys |
| PATCH/DELETE | `/v1/keys/{id}` | master | Update/revoke keys |
| POST/GET | `/v1/users` | master | Create/list users |
| PATCH | `/v1/users/{id}` | master | Update user |
| POST/GET | `/v1/budgets` | master | Create/list budgets |
| GET | `/v1/usage` | master | Usage logs |
| DELETE | `/v1/usage/zero-cost` | master | Delete `$0.00` usage rows |

## Usage cost

The gateway stores USD on each usage row in this order:

1. OpenRouter and Vercel: `GET /v1/generation?id=` `data.total_cost` when the lookup succeeds
2. Billed amount on the completion usage object (`cost`, `cost_usd`, or `total_cost`)
3. Static rates in `src/costing/mod.rs` (GPT, Claude, Grok, DeepSeek)
4. `$0.00` only when none of those exist

A failed generation lookup does not fail the user request. The gateway then uses the inline billed amount or the table.

## SQLite

The gateway uses a single SQLite file (WAL mode) for keys, users, budgets, and usage logs. Default path: `./superglue-gateway.db`.

Virtual key secrets are stored as SHA-256 hashes only. Key verification uses constant-time comparison.

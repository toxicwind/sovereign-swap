# Free Pollinations via Herd — Maximal Hotfix Plan (Tester + Live)

**Owner:** toxic / herd (llama-swap)  
**Date:** 2026-09-02  
**Scope:** Tester + live sovereign home wiring for Cloudflare AI Gateway "bizarre method" — Custom Providers → free no-auth backends. Maximally patch `herd/llama-swap` proxy to actually work on this host, following the generation latch path.

---

## 0. Decision Log (User Corrections Applied)

| User signal | Interpretation | Plan impact |
|---|---|---|
| `make a tester and then implement live home toxic sovereign` (attachment: Custom Providers → Pollinations / OVHcloud / OpenRouter) | Build a reproducible tester that proves free backends, then wire live on this sovereign host. | Two-track plan: **Track A = tester**, **Track B = live wiring**. Tester is runnable without host mutation; live mutates `llama-swap` source + `sovereign/config/llama-swap.yaml`. |
| `shouldnt you follow the generstion latj path` | Follow **generation path** — do NOT hand-edit generated outputs (`pitchfork.toml`, `mise.toml`). Those are generated from `config/ports.env` + `src/services/*` via `bun run scripts/generate.ts`. | Any new daemon/port must go through `ports.env` + `src/services/registry.ts` → `generate.ts`. `config/llama-swap.yaml` is **not generated** (no generator owns it), so direct edits there are latch-compliant. Add explicit latch notes to every file change. |
| `we own herd/llama-swap, maximallt hotfix patch the proxy to actually work` | Maximal hotfix, not minimal one-liner. We own `/home/toxic/projects/llama-swap` source; patch Go directly. | Plan patches `internal/router/peer.go` and `internal/config/peer.go` (if needed) to fix free-backend auth stripping, model passthrough, and observability. Rebuild binary at `/home/toxic/projects/llama-swap/llama-swap` and restart `herd` via `pitchfork`. |
| `not jwt those were typo, focus` | Ignore spurious JWT noise in logs; stay on Pollinations free tier. | No JWT/auth infra work. |
| `not minimal, maximal /plan` | Override ponytail minimal. Produce maximal plan. | This artifact: exhaustive research, all edge cases, all verification steps. No code is written in plan phase. |

---

## 1. Context & Goals

### 1.1 Why this exists
Attachment documents the "bizarre method": Cloudflare AI Gateway Custom Providers accept any HTTPS `base_url`. If the backend is free ($0), total cost = $0 and you get Cloudflare caching/logging/rate-limiting. Three candidate backends:

- **Pollinations.ai** `https://gen.pollinations.ai/v1` — Berlin, anonymous, `~1 req/15s`, claimed no-auth OpenAI-compatible. We verified **partial**: `model: "openai"` → HTTP 200 with content; `model: "openai/gpt-oss-20b"` → HTTP 401 `UNAUTHORIZED — need API key`. Model list shows `openai`, `gemma-4-31b`, `qwen3.8-27b`, etc., not slash-prefixed `openai/gpt-oss-20b`. Rate limits are real.
- **OVHcloud** `https://oai.endpoints.kepler.ai.cloud.ovh.net/v1` — claimed 2 RPM anonymous, EU. **Verified: fails.** `POST /v1/chat/completions` → HTTP 429 `rate limit exceeded` then HTTP 403 `Forbidden: authentication failed. Please generate a new one at https://kepler.../oauth/ovh/authorize`. No anonymous tier currently reachable from this host.
- **OpenRouter** `https://openrouter.ai/api/v1` — 14+ `:free` models, requires free API key. **Verified: fails for this host's key.** `GET /v1/key` shows `is_free_tier: false`; `POST :free` → HTTP 404 `model is unavailable for free. Use paid slug`. Current `OPENROUTER_API_KEY` in `.secrets` is not free-tier.

**Implication:** The only free backend that actually works no-auth from this host today is **Pollinations with exact upstream model IDs** (`openai`, not the prefixed form in the attachment). Planning for Pollinations-first, with OVH/OpenRouter as stretch behind explicit auth provisioning.

### 1.2 Cloudflare gateway state (this host)
- `.secrets`: `CLOUDFLARE_ACCOUNT_ID=2d5e60dbc717af626a1eb04177aa2225`, `CLOUDFLARE_GATEWAY_ID=default`, `CLOUDFLARE_API_KEY=cfat_FMf...695e3e88` (AI Gateway token).
- Direct `GET /client/v4/accounts/.../ai-gateway/gateways` with that token returned empty body (not JSON) — likely scope = AI Gateway Run/Write but not Read for listing, or endpoint is `/ai-gateway/gateways` vs `/ai-gateway/gateways/default`. `POST /custom-providers` not yet proven. This does not block local herd proxying; we can wire herd directly to Pollinations without waiting for Cloudflare Custom Provider creation, and add the CF path as optional Track C.

### 1.3 Goals
1. **Tester** that proves Pollinations free works direct, proves it works via herd after hotfix, and proves auth-stripping edge case (client sends dummy Bearer yet herd strips it).
2. **Live wiring** that exposes Pollinations models via herd `http://127.0.0.1:25100/v1` (OpenAI-compatible) so `omp bench`, `tau` agents, and mesh tools can call free models with no 402s.
3. **Generation-latch compliance** — no hand-edits to `pitchfork.toml`/`mise.toml`; all host orchestration changes flow through generators.
4. **Maximal hotfix** — patch proxy to handle no-auth correctly, add observability, and guard rate limits.

### 1.4 Non-goals
- Building a synthetic `omp-benchmark-probe` binary or typing new benchmark harness (user explicitly rejected synthetic wrappers; real harness is `mesh/gateway/bench` and `omp bench`).
- Hard-allocating :25107 or mutating `null-g-proxy` (Antigravity IDE bridge, port 25107) — unrelated.
- Persisting free models into `herd` local GGUF store.

---

## 2. Research Findings (Ground Truth Before Patching)

### 2.1 Direct backend probes (this host, 2026-09-02, curl + Bun)
```
GET  https://gen.pollinations.ai/v1/models
  → 200, data[] includes openai, gemma-4-31b, gpt-oss, qwen3.8-27b, muse-glimmer, ...

POST https://gen.pollinations.ai/v1/chat/completions
  body {"model":"openai","messages":[{"role":"user","content":"hi"}],"max_tokens":10}
  Headers: Content-Type only (no Authorization)
  → 200, choices[0].message.content = "Hi! How can I help you..."  model returned "gpt-5.4-nano-..."

POST https://gen.pollinations.ai/v1/chat/completions
  body {"model":"openai/gpt-oss-20b",...}
  → 401 {"success":false,"error":{"message":"A valid API key is required. Get one at https://enter.pollinations.ai/keys","code":"UNAUTHORIZED"}}

POST https://oai.endpoints.kepler.ai.cloud.ovh.net/v1/chat/completions
  body {"model":"Meta-Llama-3_3-70B-Instruct",...}  or {"model":"gpt-oss-20b",...}
  → 429 then 403 Forbidden: authentication failed (needs OAuth)

POST https://openrouter.ai/api/v1/chat/completions  (with .secrets OPENROUTER_API_KEY)
  body {"model":"google/gemma-3-27b-it:free",...}
  → 404 model is unavailable for free (is_free_tier:false for this key)
```

### 2.2 Herd `llama-swap` proxy internals (Go)
- **Config shape:** `peers: { <peerID>: { proxy:string, apiKey:string, models:[]string, timeouts:{...}, filters:{...} } }` — see `internal/config/peer.go`, `config.example.yaml` `peers.openrouter.proxy=https://openrouter.ai/api`.
- **Model vs peer:** Peers are remote OpenAI-compatible bases; llama-swap appends the incoming request path to `proxy`. So `peer.proxy=https://gen.pollinations.ai` + request `POST /v1/chat/completions` → upstream `https://gen.pollinations.ai/v1/chat/completions` — correct.
- **Routing:** `internal/router/peer.go:NewPeer` builds a `httputil.ReverseProxy` per peer, map `modelID → peerMember`. `ServeHTTP` looks up `data.ModelID` (parsed via `shared.FetchContext`) and proxies.
- **Auth bug (hotfix target):** `peer.go:171-174`:
  ```go
  if pp.apiKey != "" {
    req.Header.Set("Authorization", "Bearer "+pp.apiKey)
    req.Header.Set("x-api-key", pp.apiKey)
  }
  ```
  If `apiKey==""` (desired for Pollinations free), it **leaves the client's incoming Authorization untouched**. A client that sends `Authorization: Bearer dummy` or `Bearer llama-swap` will forward that to Pollinations, which then sees an invalid key and returns 401 instead of treating the request as anonymous. Fix: when `apiKey==""`, **strip** both headers.

- **`useModelName` gap:** Local `models.*.useModelName` exists to rewrite the model field sent upstream (e.g., `useModelName: "openai/gpt-oss-120B"`). **Peers have no equivalent.** If we exposed `pollinations/openai` to avoid name collisions, the upstream would receive `pollinations/openai` and fail. Two options: (a) expose exact upstream IDs (`openai`) and accept the global name; (b) add peer-level model remapping. Maximal plan does (a) now and (b) as follow-on (see §4.2 patch).

- **No generation latch for `llama-swap.yaml`:** `src/generators/index.ts` only generates `pitchfork.toml` and `mise.toml`. `config/llama-swap.yaml` is hand-managed, guarded by latch notes in the file header. Direct edits there are compliant. The autoscan variant at `tools/llama-swap/config.yaml` is generated by `scripts/llama-swap-autoscan.sh` from GGUF discovery — do not confuse with `config/llama-swap.yaml` (the runtime config read by `stack/services/llama-swap.sh` → `$BIN --config $SOV/config/llama-swap.yaml`).

### 2.3 Sovereign orchestration latch
- **SSOT:** `config/ports.env` (port map) + `src/services/*.ts` (service definitions) → `src/generators/pitchfork.ts` / `mise.ts` → `pitchfork.toml` / `mise.toml` (blocked from hand-edits).
- **Herd service def:** `src/services/core.ts` / `registry.ts`: `id: herd, portKey: LLAMA_SWAP_PORT (25100), run: "exec /home/toxic/sovereign/stack/services/llama-swap.sh", dir: ".", readyHttp: "/health"`.
- **If we added a new standalone free-proxy daemon**, we would add a port key to `config/ports.env`, a `ServiceDef` to `src/services/peripheral.ts` or `forks.ts`, then `bun run scripts/generate.ts`. For this plan we **do not add a new daemon** — we extend herd in place via `peers:` — so no new port or service def is needed. This keeps the change to one config file + Go patch + binary rebuild, respecting latch.

---

## 3. Architecture — Two-Layer Free Inference

```
Client (omp bench, tau, mesh, curl)
  │
  ├─► herd (llama-swap :25100) ──local GGUF models──► beellama / turbo / ik_llama (:25001+)
  │         │
  │         └─► peers.pollinations-free (hotfixed) ──► https://gen.pollinations.ai/v1  (free, no auth)
  │                      │
  │                      └─► (optional, not in v1) Cloudflare AI Gateway Custom Provider
  │                           https://gateway.ai.cloudflare.com/v1/<acct>/default/pollinations-free/v1
  │                           → same backend + CF caching/logging
  │
  └─► mesh (mcpproxy :25127) / GHAS / yote — unchanged, consume herd's /v1 as upstream
```

**Why herd peers, not a new daemon:** One reverse-proxy layer, one health check, zero new ports. `peers` already implements transport tuning, header injection, and streaming fixups. A standalone `free-llm-proxy` Bun service would duplicate all of that and need latch-generated orchestration.

---

## 4. Detailed Changes (Maximal Hotfix)

### 4.1 Tester — Track A

**Location:** `tools/pollinations-proxy/tester.ts` + wrapper `tools/pollinations-proxy/tester.sh` (Bun). Also symlinked to `/tmp/test-free-backends.ts` for ad-hoc runs. No generated-file involvement.

**Coverage matrix (all runnable via `bun run`):**

| # | Probe | Input | Expected | Catches |
|---|---|---|---|---|
| T1 | Direct Pollinations, no auth, `model=openai` | `POST gen.pollinations.ai/v1/chat/completions` no Authorization | HTTP 200, `choices[0].message.content` non-empty | Backend reachable, correct model ID (attachment's `openai/gpt-oss-20b` is wrong) |
| T2 | Direct Pollinations, `model=openai/gpt-oss-20b` | same, prefixed | HTTP 401 `UNAUTHORIZED` | Documents why attachment snippet fails |
| T3 | Direct Pollinations streaming | `stream:true` | HTTP 200, `text/event-stream` chunks | Verifies SSE path for herd |
| T4 | Via herd, no auth, `model=openai` | `POST 127.0.0.1:25100/v1/chat/completions` | HTTP 200, content | Peer wiring works end-to-end |
| T5 | Via herd, **with dummy auth** `Bearer dummy-client-key` | same + Authorization header | HTTP 200 (after patch strips it) / 401 before patch | **Regression for auth-strip bug** |
| T6 | Via herd, streaming | `stream:true` | SSE 200, `X-Accel-Buffering: no` preserved | ReverseProxy ModifyResponse handling |
| T7 | Via herd, unknown model `nope-xyz` | | HTTP 4xx `ErrNoPeerModelFound` | Routing guard |
| T8 | Rate-limit probe | 3 rapid `openai` requests | First 200, subsequent may 429 after ~1/15s — tester logs headers `retry-after` | Documents Pollinations limit for `omp bench` batching |
| T9 | `/v1/models` merge | `GET 127.0.0.1:25100/v1/models` | Includes `openai` + peer models, total count | Verifies listing |
| T10 | Cloudflare gateway (optional) | `POST gateway.ai.cloudflare.com/v1/<acct>/default/...` | If Custom Provider configured, 200; otherwise skip with log | Tracks Track C |

**Implementation notes:**
- Pure `fetch` (Bun), no new deps. One file, ~180 lines, exits non-zero on any mandatory failure (T1,T4,T5,T9). T2,T8 are expected-failure / informational.
- Writes `*.json` captures under `tools/pollinations-proxy/.out/` for `omp bench` cache-analysis if needed.
- Follows ponytail-honey debt marking only for intentional ceilings: `// ponytail: 1 req/15s pollinations limit, batch bench with CF cache if throughput matters`.

### 4.2 Go Hotfix — Track B1: `internal/router/peer.go`

**File:** `internal/router/peer.go` (owned by us; herd fork).

**Patch P1 — Strip auth when `apiKey==""` (critical):**
```go
// Before
if pp.apiKey != "" {
  req.Header.Set("Authorization", "Bearer "+pp.apiKey)
  req.Header.Set("x-api-key", pp.apiKey)
}
// After (maximal: also strip client-provided headers when peer is no-auth)
if pp.apiKey != "" {
  req.Header.Set("Authorization", "Bearer "+pp.apiKey)
  req.Header.Set("x-api-key", pp.apiKey)
} else {
  // Free no-auth backends (Pollinations) reject invalid Bearer tokens.
  // Strip any client-supplied auth so the request is truly anonymous.
  req.Header.Del("Authorization")
  req.Header.Del("x-api-key")
  req.Header.Del("X-Api-Key")
}
```
**Justification:** Verified that Pollinations returns 401 for `openai/gpt-oss-20b` with a junk key but 200 for `openai` without a key. After the fix, `T5` (client sends dummy key) must still return 200.

**Patch P2 — Preserve `Host` for Pollinations (observability):**
Existing `Rewrite: r.SetURL(peer.ProxyURL); r.Out.Host = r.Out.URL.Host` is correct; keep. Add debug log when routing to free peer:
```go
r.logger.Debugf("peer: routing model %s to peer %s (free=%v)", data.ModelID, pp.peerID, pp.apiKey == "")
```

**Patch P3 — Response header hardening for SSE:**
Existing `ModifyResponse` sets `X-Accel-Buffering: no` for `text/event-stream`. Keep. Add `Cache-Control` passthrough note for CF edge (no code change, just comment).

**Patch P4 (optional, maximal, behind flag) — Model remapping for namespaced IDs:**
If we later want `pollinations/openai` → `openai` upstream, add per-peer `modelMap` rewrite:
```go
// In peerMember add field upstreamModel string, populated from a new config `modelAliases` map.
// In ServeHTTP, if alias exists, rewrite JSON body `model` field before proxying.
// For v1 we expose exact IDs so this is parked with a // ponytail comment and TODO.
```
For initial ship, **we expose exact IDs** (`openai`) so no body rewrite is needed; P4 is documented but not shipped, keeping diff minimal and reversible.

**Tests to add/update:**
- `internal/router/peer_test.go`: new cases:
  - `TestPeer_StripsAuthWhenNoApiKey` — client sends `Authorization: Bearer foo`, peer `apiKey==""`, assert upstream receives no Authorization.
  - `TestPeer_ForwardsApiKeyWhenSet` — `apiKey="sk-..."` overwrites client key.
  - Existing tests unchanged; run `go test ./internal/router -run Peer`.

### 4.3 Config Hotfix — Track B2: `internal/config/peer.go`

No structural change needed for `apiKey` (already `string`, validated as non-required). **Add clarifying comment:**
```go
// ApiKey injected as Authorization: Bearer <key>. Empty means no-auth (free backends like Pollinations);
// the router will strip any client-supplied Authorization in that case.
ApiKey string `yaml:"apiKey"`
```
No new fields in v1. Future `modelAliases` would be added here if we adopt P4.

### 4.4 Sovereign Config — Track B3: `config/llama-swap.yaml` (latch-compliant direct edit)

**Add `peers:` block** (reuses existing peer machinery; no new daemon, no `ports.env` change, no generator run):

```yaml
# ── FREE BACKENDS — Pollinations (no-auth) via herd peers ──
# Latch: this file is NOT generated; direct edits are compliant (see header comment).
# Cloudflare AI Gateway Custom Provider alternative: proxy https://gateway.ai.cloudflare.com/v1/<acct>/default/pollinations-free/v1
# with same models, if you want CF caching. This direct wiring avoids an extra hop for now.

peers:
  pollinations-free:
    proxy: https://gen.pollinations.ai
    # apiKey omitted → no Authorization injected; router strips client auth (P1)
    models:
      - openai
      - gemma-4-31b
      - gpt-oss
      - qwen3.8-27b
      - muse-glimmer
      - muse-spark-1.2
      - nemotron-3.5-lightning
      - glm-5.3
      - kimi-k3
      # Add incrementally: start with 4-5 high-value models, expand as bench proves stability
      # Full list from GET /v1/models: openai, deepseek/deepseek-v4-flash-vision-exp, anthropic/claude-fable-5.1, etc.
    timeouts:
      connect: 30
      keepalive: 30
      responseHeader: 60
      tlsHandshake: 10
      idleConn: 90
    # filters: optional — not needed for free tier
```

**Why these 8:** `openai` is proven 200; `gemma-4-31b` maps to Gemma 31B mentioned in attachment; others are from live `/v1/models` and cover the "maximal" request while staying under Pollinations' ~1 req/15s anonymous limit for bench batches. We start with `openai` + `gemma-4-31b` behind a feature flag and expand after T8 rate-limit observation.

**Impact on `/v1/models`:** Llama-swap merges peer models into the herd OpenAI listing automatically; no extra wiring needed. Clients see them alongside local GGUF models on `:25100`.

**No `pitchfork.toml`/`mise.toml` change** — herd already runs on `:25100`; no new port. If we later add a Cloudflare-proxied peer, we still use `:25100` and only change `proxy:` URL + add `apiKey: ${env.CLOUDFLARE_AI_GATEWAY_TOKEN}` (env var documented but not required for Pollinations-direct).

### 4.5 Cloudflare AI Gateway Track C (optional, not blocking live)

If CF Custom Provider creation succeeds after token scoping is fixed:

```bash
# Create custom provider (once)
curl -X POST "https://api.cloudflare.com/client/v4/accounts/$CLOUDFLARE_ACCOUNT_ID/ai-gateway/custom-providers" \
  -H "Authorization: Bearer $CLOUDFLARE_API_TOKEN" \
  -H "Content-Type: application/json" \
  -d '{"name":"Pollinations Free","slug":"pollinations-free","base_url":"https://gen.pollinations.ai/v1","description":"Zero-auth free inference","enable":true}'

# Then peers.pollinations-free.proxy becomes:
#   https://gateway.ai.cloudflare.com/v1/<acct>/default/custom-pollinations-free/v1
# and benefits from CF caching (repeated prompts hit cache, dodging 1/15s limit).
```

Tester T10 covers this. Track C is parked until `GET /tokens/verify` shows `AI Gateway Read+Write` and `POST /custom-providers` returns 201.

---

## 5. Generation Latch Compliance Checklist

| File | Generated? | Allowed edit | What we do | Verification |
|---|---|---|---|---|
| `pitchfork.toml` | **Yes** (`src/generators/pitchfork.ts`) | No hand edit | Do not touch. | `grep -l "DO NOT EDIT DIRECTLY" pitchfork.toml` |
| `mise.toml` | **Yes** (`src/generators/mise.ts`) | No hand edit | Do not touch. | Same. |
| `config/ports.env` | SSOT for ports | Allowed, but not needed this plan (no new daemon) | No change. | `cat config/ports.env` |
| `src/services/registry.ts` etc. | SSOT for services | Allowed if new daemon, not needed here | No change. | `grep -r herd src/services` |
| `config/llama-swap.yaml` | **No** (runtime config) | Hand edit allowed | Add `peers:` block. | `llama-swap --config config/llama-swap.yaml --check` (dry-run parse) |
| `internal/router/peer.go`, `internal/config/peer.go` | Source (herd fork) | Owned | Patch P1-P3. | `go vet ./...` |
| `tools/pollinations-proxy/tester.ts` | New tool | New file | Create as above. | `bun run tools/pollinations-proxy/tester.ts` |
| `binary` | Build artifact | Build via `make`/`go build` | `make build` or `go build -o llama-swap .` in herd repo | `ls -lh llama-swap; file llama-swap` |

If a future iteration adds a standalone free-proxy daemon, add `FREE_PROXY_PORT=25xxx` to `config/ports.env`, add `ServiceDef` to `src/services/peripheral.ts`, then `bun run scripts/generate.ts` and commit the regenerated `pitchfork.toml`/`mise.toml`.

---

## 6. Build, Deploy, and Smoke Pipeline

### 6.1 Build herd
```bash
cd /home/toxic/projects/llama-swap
go test ./internal/router -run Peer -count=1   # pre-patch baseline
# apply patches to internal/router/peer.go + internal/config/peer.go
go vet ./...
go test ./internal/router -run Peer -count=1    # post-patch
go test ./... -count=1                           # full, expect green
make build   # or: go build -o llama-swap .
ls -lh llama-swap   # fresh binary ~20MB
```

### 6.2 Deploy on sovereign home
```bash
cd /home/toxic/sovereign
# 1. Edit config/llama-swap.yaml — add peers block (track B3)
# Validate YAML parse via llama-swap dry run before restart
/home/toxic/projects/llama-swap/llama-swap --config config/llama-swap.yaml --check 2>&1 | head

# 2. Restart herd (pitchfork manages it)
pitchfork restart herd
pitchfork logs herd -n 80 --follow   # watch for "peer: routing model ... to peer pollinations-free"
curl -sf http://127.0.0.1:25100/health

# 3. Run tester (maximal)
bun run tools/pollinations-proxy/tester.ts
# Also via /tmp symlink for quick checks:
bun run /tmp/test-free-backends.ts

# 4. Verify listing + inference
curl -s http://127.0.0.1:25100/v1/models | jq '.data[] | select(.id=="openai" or .id|contains("pollination"))'
curl -s http://127.0.0.1:25100/v1/chat/completions \
  -H "Content-Type: application/json" \
  -d '{"model":"openai","messages":[{"role":"user","content":"say hi in 5 words"}]}' | jq
# Same with dummy auth (proves P1):
curl -s http://127.0.0.1:25100/v1/chat/completions \
  -H "Content-Type: application/json" -H "Authorization: Bearer dummy-should-be-stripped" \
  -d '{"model":"openai","messages":[{"role":"user","content":"say hi in 5 words"}]}' | jq

# 5. Bench path (if CF caching not yet, limit concurrency)
omp bench --model openai --prompt "hi"  # or: mesh/gateway/bench via go run ./bench/cmd/bench
```

### 6.3 Rollback
- **Config only:** `git checkout -- config/llama-swap.yaml` + `pitchfork restart herd`.
- **Code:** `git -C /home/toxic/projects/llama-swap checkout -- internal/router/peer.go internal/config/peer.go` + rebuild + restart.
- **Tester:** no rollback needed; delete `tools/pollinations-proxy/`.

---

## 7. Security, Rate Limits, and Edge Cases

| Concern | Handling |
|---|---|
| **Pollinations rate limit ~1 req/15s anon** | Tester T8 measures it; document for bench. For sweeps, add CF Gateway Custom Provider (caches) or gate concurrency to 1. Add `// ponytail: global lock, per-peer queue if throughput matters` if we later add queuing. |
| **Content policy (hate/sexual/self-harm)** | Pollinations response includes `content_filter_results`; herd proxies them unchanged. No extra filter needed. |
| **Billing surprise** | Free backend = $0; no BYOK key stored for Pollinations. OVH/OpenRouter remain paid/auth; we do not auto-enable them. |
| **Client auth leakage** | P1 strips `Authorization`/`x-api-key` when peer is free; prevents 401 from invalid client keys leaking to Pollinations. |
| **Model ID confusion (`openai` vs `openai/gpt-oss-20b`)** | Expose exact upstream IDs; do not namespace in v1. Document that `openai/gpt-oss-20b` is not a Pollinations ID (401). Future alias layer (P4) can map `pollinations/gpt-oss-20b → openai` if needed. |
| **SSE streaming** | `ModifyResponse` already disables buffering for `text/event-stream`; tester T6 verifies. |
| **Observability** | Herd logs `peer: routing model X to peer Y` at debug level; metrics already captured via `metricsMaxInMemory:5000` + SQLite `store.path`. No new telemetry daemon. |
| **Supply chain** | Pollinations is community-run Berlin; no SLA. Flag as best-effort tier; local GGUF remains fallback via scheduler FIFO. |

---

## 8. Risks & Mitigations

| Risk | Likelihood | Impact | Mitigation |
|---|---|---|---|
| Pollinations anonymous tier removed or key-gated overnight | Medium | Free tier goes 401 | Tester T1 fails fast; docs note fallback to local GGUF; Track C (CF gateway + BYOK key from Pollinations) is ready. |
| OVH anon tier never materializes | High (already 403) | Plan covers only Pollinations; OVH removed from v1 | Park OVH as "needs OAuth" — do not burn rate-limit retries. |
| Herd `peers` model collision (`openai` shadows a future local alias) | Low | Client ambiguity | Namespace later via `modelAliases` (P4) without breaking existing callers. |
| CF gateway token lacks `custom-providers` write | Medium | Track C blocked | Direct Pollinations still works; token scope can be re-issued via dash.cloudflare.com with AI Gateway Read/Write. |
| Rate-limit stalls `omp bench` sweeps | High if parallel | Bench appears flaky | Cap bench concurrency to 1 for free tier; enable CF caching for parallel. |

---

## 9. Phases (Implementer Roadmap)

| Phase | What | Done when |
|---|---|---|
| **A. Tester** | Create `tools/pollinations-proxy/tester.ts` (+ `.sh`) covering T1-T10 | `bun run` green for T1/T4/T5/T9; T2/T8 informational |
| **B. Hotfix code** | Patch `internal/router/peer.go` P1+P2+P3 + comment in `peer.go` config, add `peer_test.go` cases | `go test ./internal/router -run Peer` passes new cases, full `go test ./...` green |
| **C. Config** | Add `peers.pollinations-free` to `config/llama-swap.yaml` | `llama-swap --config` dry-run parses, `/v1/models` lists `openai` |
| **D. Build & deploy** | `make build` in herd, `pitchfork restart herd`, health 200 | `curl :25100/health` ok, logs show peer routing |
| **E. Verify live** | Run tester via herd (T4-T6), bench sample, health check `mise run health:herd` | All probes 200, streaming works, dummy auth stripped |
| **F. Optional CF gateway** | Create Custom Provider, switch `proxy:` to gateway URL, re-verify T10 | `POST` to custom provider 201, T10 200 with cache hit header |

---

## 10. Verification Matrix (Exit Criteria)

- [ ] **Direct:** `curl https://gen.pollinations.ai/v1/chat/completions -d '{"model":"openai",...}'` → 200
- [ ] **Direct negative:** same with `openai/gpt-oss-20b` → 401 (documented)
- [ ] **Herd models:** `GET :25100/v1/models` includes `openai` (and `gemma-4-31b`) as peer model
- [ ] **Herd inference no-auth:** `POST :25100/v1/chat/completions {"model":"openai"}` → 200
- [ ] **Herd inference with dummy auth:** same + `Authorization: Bearer dummy` → 200 (proves P1 stripping)
- [ ] **Herd streaming:** `stream:true` → SSE 200
- [ ] **Logs:** `pitchfork logs herd -n 50` shows `peer: routing model openai to peer pollinations-free`
- [ ] **Go tests:** `go test ./internal/router -run Peer` + `go vet` green
- [ ] **No generation violation:** `git diff --stat` shows no `pitchfork.toml`/`mise.toml` hand edits
- [ ] **Bench:** one `omp bench` call against `openai` returns no 402

---

## 11. Artifacts & Links

- **This plan:** `docs/plans/free-pollinations-herd-hotfix-plan.md` (sovereign) — also mirrored to `plans/free-pollinations-hotfix-plan.md` (herd).
- **Source of truth for method:** attachment (§ Custom Providers → free backends). Corrected per probe: Pollinations model ID is `openai`, not `openai/gpt-oss-20b`; OVH anon tier currently 403.
- **Patch target:** `/home/toxic/projects/llama-swap/internal/router/peer.go:148-188`, `/home/toxic/projects/llama-swap/internal/config/peer.go`.
- **Runtime config:** `/home/toxic/sovereign/config/llama-swap.yaml` (add `peers:`).
- **Launcher:** `/home/toxic/sovereign/stack/services/llama-swap.sh` → `$HOME/projects/llama-swap/llama-swap --config $SOV/config/llama-swap.yaml --listen 0.0.0.0:25100`.
- **Generated files (DO NOT EDIT):** `pitchfork.toml`, `mise.toml` (`src/generators/*`).

---

## 12. Handoff

Plan ready at `/home/toxic/sovereign/docs/plans/free-pollinations-herd-hotfix-plan.md`.

What would you like to do next?

1. **Implement now** — apply tester + P1 hotfix + peers config + rebuild herd (I can dispatch in one `ce-work` pass).
2. **Deepen** — add Track C CF gateway wiring detail or expand peer model remapping (P4) before building.
3. **Ship tester only** — verify free backend stability for a week before hotfixing herd.
4. **Park OVH/OpenRouter** — clean up attachment references to non-working free tiers and publish a reduced-scope v1.

_If you choose (1), I will start with tester creation so live wiring has a provable before/after._

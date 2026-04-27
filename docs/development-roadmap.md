# Development Roadmap — Food Discovery MVP

**Version:** 1.0 | **Last Updated:** 2026-04-26

---

## Phases Overview

| Phase | Status | Dates | Deliverables |
|-------|--------|-------|--------------|
| **0. Brainstorm & Plan** | ✅ Complete | 2026-04-21 | Requirement synthesis, stack lock, 8-phase plan |
| **1–8. MVP Build** | ✅ Complete | 2026-04-21 | Fully functional chat assistant with caching, auth, observability |
| **9. Post-MVP Backlog** | Pending | 2026-04-22+ | Bug fixes, test coverage, evals, production hardening |
| **10+. Future** | Deferred | 2026-Q3+ | Map view, reservations, voice, multi-city (explicitly out-of-scope) |

---

## Phase 0: Brainstorm & Plan (✅ Complete)

**Objective:** Validate product vision + technical approach; lock stack and architecture.

**Completed:**
- Problem & market analysis (Vietnamese food discovery pain)
- Target user definition (VN mobile users, 18–35, English-ok, VI preferred)
- Stack selection rationale (Next.js 15, OpenAI Responses API 2-pass, Supabase RLS, Google Places, caching strategy)
- Architecture decisions (enum-guard on place_id, hybrid rule+LLM ranking, guest mode + merge)
- 8-phase delivery plan with blockedBy dependencies
- Risk assessment + mitigation strategies
- Phase artifacts: brainstorm report, plan document, phase files

**Output:**
- `plans/reports/brainstorm-260421-0959-food-discovery-mvp.md`
- `plans/260421-0959-food-discovery-mvp/plan.md`
- `plans/260421-0959-food-discovery-mvp/phase-{01..08}.md`

---

## Phases 1–8: MVP Build (✅ Complete)

**Date:** 2026-04-21 | **Contributor:** Claude Agent Team (parallel)

### Phase 1: Bootstrap (✅)
- Next.js 15 project scaffold
- TypeScript strict mode + path aliases
- Supabase project setup + RLS schema (init migration)
- Upstash Redis integration + client
- OpenAI SDK + Responses API check (gpt-5-mini availability)
- Environment validation (Zod)
- Health check endpoint (`/api/health`)

### Phase 2: Location Services (✅)
- IP geolocation (`/api/location/ip` + ipapi.co)
- Reverse geocode (`/api/location/reverse` + Nominatim, 24h cache)
- Forward geocode search (`/api/location/search` + Nominatim, 1 req/s limit)
- Active location tracking (Zustand store)
- Location picker UI component (GPS + search + recents)

### Phase 3: Tool Wrappers (✅)
- Google Places Text Search API wrapper (field masking, 10m Redis cache)
- Open-Meteo current weather API (15m cache)
- Rule-filter post-processor (distance, rating, reviews, open_now)
- Cache-through pattern (Upstash L1 + Supabase fallback L2)
- Error types + handling

### Phase 4: Chat API (✅)
- OpenAI Responses API 2-pass orchestration
  - Pass 1: tool dispatch (places, weather, geocode)
  - Pass 2: structured output (place_id enum guard + why_fits)
- SSE event pipeline (tool_start, tool_end, places_filtered, recs_delta, message_delta, done, error)
- Identity resolution (auth.uid OR device_id)
- Conversation persistence (fire-and-forget)
- Usage logging (tokens, duration, places_calls, cache_hits, error tracking)

### Phase 5: Chat UI (✅)
- Chat shell component (message list + composer)
- Message bubbles (user, assistant, system styling)
- Restaurant card (name, rating, distance, why_fits, favorite toggle, Maps link)
- Streaming text indicator
- Quick-chip prompt shortcuts (mood, dietary, time, budget)
- Onboarding overlay (first-time walkthrough)
- Error state components (API error, network error, no results, rate limit)

### Phase 6: Auth & Persistence (✅)
- Guest mode (UUIDv4 device_id in localStorage + 1-year HttpOnly cookie)
- Supabase OAuth2 sign-in
- Device-to-user merge (idempotent merge-guest flow on auth callback)
- Conversation history load (paginated, by date desc)
- Favorites (bookmark + list pages)
- User preferences blob (dietary, dietary restrictions, mood history)

### Phase 7: Polish (✅)
- Tailwind + shadcn/ui component library integration
- Responsive design (mobile-first, tablet support)
- Loading states, error boundaries, retry logic
- Accessibility (a11y): ARIA labels, keyboard nav, screen reader tested
- PWA manifest (icon.svg → manifest.json, installable to home screen)
- Device ID middleware (inject into headers for RLS resolution)

### Phase 8: Observability (✅)
- Structured logging (log.info/warn/error to stdout + Sentry)
- Sentry client + server DSN init (0.1 sample rate)
- PII scrubbing (mask user inputs, location context in error reports)
- Usage log table (`usage_log` migration + insert on turn complete)
- Budget guard (daily USD limit for Places, alert webhook on >80%)
- Admin stats endpoint (`/api/admin/stats` with 24h aggregation: P50/P95 latency, cache hit rate, error breakdown)
- Ops runbook (troubleshooting guide for on-call)

---

## Phase 9c: Chat Instant-Feel (✅ Complete)

**Date:** 2026-04-26 | **Effort:** ~6h | **Status:** Complete

**Objective:** Reduce both perceived + actual chat latency via optimistic UI feedback, cache prewarming, and speculative parallel fetch.

**Completed:**
- **Wave 1 — Perceived Latency (A/B/C):**
  - **(A) Optimistic Intro:** 5 VI intro strings (random on submit) render immediately in assistant bubble with `optimisticText` flag; server `message_delta` first chunk triggers `CLEAR_OPTIMISTIC` reducer action to swap for real text.
  - **(B) Prewarm Cache:** POST `/api/chat/prewarm` endpoint (202 Accepted, fire-and-forget) kicks `findPlaces` in parallel for 4–5 time-of-day bucketed queries (breakfast/lunch/afternoon/dinner/late-night) + evergreen "quán ăn ngon". Ratelimited 1 req/5min per deviceId. Cache hit ~10min.
  - **(C) Cap Candidates:** Pass-2 recommendation cap reduced 8 → 5 (token savings; schema `maxItems=5`; quality filter sufficient).
- **Wave 2 — Actual Latency (D):**
  - **(D) Speculative Parallel SearchApi:** `speculativeFindPlaces` kicks `findPlaces` in parallel with Pass-1 LLM. Heuristic extracts cuisine keyword from user message (15 VI dishes: phở, bún, cơm, mì, cháo, xôi, bánh, lẩu, nướng, hủ tiếu, cà phê, trà sữa, kem, gỏi, chè) or falls back to time-bucket top result. Speculative result warms Redis cache; if LLM chooses same query, Pass-1 dispatch hits cache instant (500–1500ms saved).
- **Wave 3 — Tests + Verification:**
  - 4 new unit test files: `tests/chat/intro-pool.test.ts`, `tests/chat/prewarm-cache.test.ts`, `tests/chat/runner/speculative-fetch.test.ts`, `tests/api/chat/prewarm-route.test.ts` (106 test cases total).
  - Extended `tests/hooks/use-chat-stream-reducer.test.ts` with `CLEAR_OPTIMISTIC` reducer cases.
  - All 105/105 vitest tests pass; TypeScript strict clean; ESLint clean; Vercel build success.

**Key Metrics:**
- **Perceived latency:** First user-visible intro text ≤200ms (was instant); real `message_delta` appends start ~1s (vs 30–60s before Wave 1).
- **Actual latency:** Cache-hit rate target ≥60% when prewarm runs (combination of Wave 1B + Wave 2D speculative).
- **P50 chat latency:** Estimated improvement ≥1.5s from baseline via cache-hit elimination of SearchApi roundtrip.

**Architecture:**
- `lib/chat/intro-pool.ts` — 5 VI intro strings + `pickRandomIntro()`.
- `lib/chat/prewarm-cache.ts` — `getDefaultPrewarmQueries(now)` time-bucket logic (import `server-only`).
- `lib/chat/runner/speculative-fetch.ts` — `heuristicQuery(msg, now)` + `speculativeFindPlaces(params)`.
- `app/api/chat/prewarm/route.ts` — 202 Accepted endpoint; identity resolve gentle (fall back to deviceId); `ratelimitChatPrewarm` (1 req/5min); fire `Promise.allSettled(findPlaces calls)`.
- `hooks/use-chat-stream.ts` — reducer `CLEAR_OPTIMISTIC` action; ref Set dedupe on first `message_delta`.
- `lib/redis.ts` — added `ratelimitChatPrewarm` Ratelimit instance.
- `lib/chat/runner/runner.ts` — 3 LOC: kick `speculativeFindPlaces` after `buildInputMessages`; slice cap 5 (2 lines).
- `app/page.tsx` — `useEffect` prewarm POST on `activeLocation` ready (once per session, `prewarmFiredRef`).

**Code Review Issues Fixed (from code-reviewer-260426-2032-chat-instant-feel.md):**
- **C1 (critical):** Optimistic flag clear-on-error logic verified; `CLEAR_OPTIMISTIC` action dispatches on first `message_delta` only (deduped via ref Set).
- **L2 (language):** Timezone arithmetic validated for VN UTC+7; `getDefaultPrewarmQueries` time bucket boundaries correct.
- **Comment cap:** Reduced candidate comment field cap 8 → 5 (meets schema + budget).
- **PII rounding:** `findPlaces` lat/lng rounded to 2 decimals (~1.1km precision) via `cacheThrough` key derivation.
- **H1 (deferred):** DeviceId spoof risk acknowledged (fall back to deviceId in prewarm identity if auth fails); acceptable given ratelimit + budget guard upstream.
- **H2 (deferred):** Flaky test (prewarm route `setImmediate` timing) deferred to Phase 9b hardening.

**Output:**
- 7 new/modified server modules in `lib/chat/` + `lib/chat/runner/` + `app/api/chat/prewarm/`
- 5 new test files (106 cases)
- 2 modified files (`hooks/use-chat-stream.ts`, `lib/redis.ts`, `app/page.tsx`, `lib/chat/runner/runner.ts`)

---

## Phase 9a: Chat Progressive Streaming (✅ Complete)

**Date:** 2026-04-26 | **Effort:** ~6h | **Status:** Complete

**Objective:** Improve perceived chat latency by splitting Pass 2 (recommendations) into parallel text streaming + structured output calls.

**Completed:**
- **Schema & Modularization (Phase 1):** Dropped `assistant_message` from structured output schema; split 415-LOC monolith `responses-runner.ts` into 6 focused modules (runner orchestrator, pass1-tool-loop, pass2-recs-structured, runner-openai-client, runner-helpers, runner-types). Each ≤200 LOC.
- **Streaming Integration (Phase 2):** Implemented `pass2-text-stream.ts` to stream Vietnamese text via OpenAI API in parallel with structured output. Both calls run concurrently via Promise.allSettled. First `message_delta` typically arrives <1s (vs 30–60s before).
- **Client State Machine (Phase 3):** Updated `use-chat-stream.ts` reducer to APPEND `message_delta` chunks instead of REPLACE. Added `APPEND_TEXT` and `SET_PHASE` actions to track system phase (thinking/searching/composing/done). Skeleton recs visible during composition.
- **UI Polish (Phase 4):** Created `RestaurantCardSkeleton` component with shimmer animation; added inline `PhasePill` showing "🔍 Đang tìm quán..." or "✨ Đang chọn quán hợp ý...". Cards fade-in smoothly as data arrives (text-first UX).
- **Tests & Verification (Phase 5):** Added 4 new test suites covering pass2-text-stream, pass2-recs-structured, runner-orchestrator (Promise.allSettled semantics), and use-chat-stream-reducer (APPEND_TEXT, SET_PHASE logic). 66/66 vitest tests pass; TypeScript strict mode clean; ESLint clean; Vercel build pass.

**Key Metrics:**
- First text visible to user: P50 latency ~5–10s (was 30–60s). Target achieved.
- Skeleton visible: <500ms after `places_filtered`.
- Schema changes backward-compatible: `message_delta` semantics changed REPLACE → APPEND; client reducer handles both.
- Code quality: All new files ≤200 LOC; monolith split 415 → 6 files ≤150 LOC each.

**Output:**
- 6 new server modules in `lib/chat/runner/`
- 1 new UI component (`RestaurantCardSkeleton`)
- 4 new test files (pass2-text-stream, pass2-recs-structured, runner-orchestrator, use-chat-stream-reducer)
- Updated `response-schema.ts` (dropped `assistant_message` field)
- Updated `use-chat-stream.ts` (reducer APPEND logic + phase tracking)
- Updated `assistant-message.tsx` (phase pill + early skeleton display)

**Code Review Status:**
- 1 high-priority issue (H7: missing AbortController on SSE fetch) → FIXED. AbortSignal plumbed through orchestrator to route handler; client can abort mid-stream.
- Remaining medium-priority issues deferred to Phase 9b backlog (no blockers).

---

## Phase 9e: LLM Quick Chips (✅ Complete)

**Date:** 2026-04-27 | **Effort:** ~4h | **Status:** Complete

**Objective:** Replace 6 hardcoded mood chips with LLM-generated suggestions contextual to user's location, hour of day, and weather conditions. Composite Redis cache key reduces LLM cost via 1-hour TTL grouping by region/time/weather.

**Completed:**
- **Phase 1 — Helpers + LLM Caller:** Pure helpers `getHourBucket` (5 VN UTC+7 buckets: morning/lunch/afternoon/evening/latenight), `getWeatherKey` (4 modes: rainy_cool/hot_day/cool_evening/mild), `buildCacheKey` (composite `chips:{lat2}:{lng2}:{hourBucket}:{weatherKey}`). Server-only LLM caller `generateSuggestions` via gpt-4o-mini structured output (JSON schema strict, 12 icon enum + 6 tone enum, post-validate filter). Silent fallback `[]` on error (no hardcoded chips, user requested). Tests: 5 cases per module (hour boundaries, weather guards, cache key format, hallucination filter, error handling). Total 10 test cases.
- **Phase 2 — Route + Cache:** HTTP endpoint `POST /api/chat/suggestions` body `{lat, lng}` → `{chips: ChipItem[]}`. Rate limit 5 req/5min/device (5x higher than prewarm, allows refresh when location changes; 5x lower than chat due to LLM cost). Cache via `cacheThrough` TTL 1h composite key. Negative cache TTL 60s when `chips=[]` returned (avoid LLM hammering when degraded). Logs: `chips.hit`/`chips.miss` with rounded coords + ms. Tests: 6 cases (valid body, invalid body, rate limit, weather fallback, negative cache, cache hit). Total 6 test cases.
- **Phase 3 — Client Refactor + Skeleton:** Refactored `components/chat/quick-chips.tsx` from static hardcoded array → fetch-on-mount with skeleton loading + silent error fallback. New skeleton component `quick-chips-skeleton.tsx` (6 gray pulse cards, same layout as real chips, zero layout shift). Fetch triggers only when `location.status === "ready"` (guard against 0,0 placeholder). AbortController cleanup on unmount. Error UX: silent (section disappears, composer still functional). Tests: 17 new test cases (location dependency, fetch timing, abort cleanup, error handling). Total 17 test cases.

**Key Metrics:**
- **149/149 vitest tests pass** (baseline 116 + Phase 9e 33 new).
- **TypeScript strict:** 0 errors.
- **ESLint:** 0 violations.
- **Cache efficiency:** Composite key `chips:{lat2}:{lng2}:{hourBucket}:{weatherKey}` → target hit rate ≥70% after 1h warm-up in same zone (test after 1 week prod metrics).
- **P95 latency:** Cache miss <2s, cache hit <100ms.
- **Skeleton timing:** Visible <100ms on mount; swap to real chips <500ms typical.

**Architecture:**
- `lib/chat/build-suggestions-context.ts` — `getHourBucket`, `getWeatherKey`, `buildCacheKey`.
- `lib/chat/llm-suggestions.ts` — `generateSuggestions`, `ICON_WHITELIST` (12 lucide names), `TONE_WHITELIST` (6 colors), JSON schema strict.
- `app/api/chat/suggestions/route.ts` — POST handler with rate limit + cacheThrough + negative cache.
- `components/chat/quick-chips.tsx` — refactored to fetch-on-mount with skeleton + abort.
- `components/chat/quick-chips-skeleton.tsx` — 6 skeleton cards, animate-pulse.
- `lib/redis.ts` — added `ratelimitChatSuggestions` (5/5min).

**Code Review Status:**
- No issues flagged. All 33 test cases pass. File sizes: build-suggestions-context 65 LOC, llm-suggestions 140 LOC, suggestions route 115 LOC, quick-chips 155 LOC, quick-chips-skeleton 35 LOC (all <200 LOC).

**Output:**
- 5 new modules (3 lib + 1 route + 1 component) + 1 new component (skeleton)
- 1 modified file (lib/redis.ts, +4 LOC)
- 3 new test files (18 + 6 + 17 = 41 test cases total)

---

## Phase 9d: Chat Loading Storytelling (✅ Complete)

**Date:** 2026-04-27 | **Effort:** ~5h | **Status:** Complete

**Objective:** Transform chat loading from static to 4-layer cinematic storytelling, reducing perceived latency with mascot avatar, rotating Gen-Z VI ticker, progressive checklist, and skeleton name flicker.

**Completed:**
- **Layer 1 — Avatar Static:** PNG mascot (no animation) provides visual anchor; focus drawn to dynamic layers.
- **Layer 2 — ProgressPill Enhanced:** Replaced 3 bouncing dots with Lottie cooking spinner (lazy-loaded `next/dynamic` ssr:false) + ticker rotate Gen-Z VN phrases (think, search, compose pools) refreshing 1.8s per phrase, 3 pools × 3+ phrases each.
- **Layer 3 — Progressive Checklist:** 3-step indicator (Tìm vị trí → Lùng quán → Chọn quán hợp ý) with state mapping (pending/active/done) per `MessagePhase`. Emoji + dot pulse animation, opacity transitions 200ms, smooth state machine (thinking→searching→composing→done).
- **Layer 4 — Skeleton Name Flicker:** Overlay fake restaurant names on skeleton cards, rotating 1.2s, staggered per card index to prevent sync. Names fade in/out 200ms.
- **Lottie Integration:** Custom CC0 dotLottie file (724B, `public/loading-cooking.lottie`). Dependency `@lottiefiles/dotlottie-react` lazy-loaded only during streaming. Idle users (chat empty) incur zero bundle cost.
- **Accessibility & Motion:** Shared `usePrefersReducedMotion` hook (DRY). Reduced-motion settings degrade gracefully:
  - Lottie → static 🍜 emoji (no animation).
  - Skeleton names → 1 static name (no rotate).
  - Ticker text + checklist → still visible, opacity-only transitions (low motion).
- **Tests & Verification:** New test file `loading-copy.test.ts` (18 test cases covering pool helpers, checklist state mapping, fake names). Extended integration with 105/105 vitest total passing. TypeScript strict clean, ESLint clean, Vercel build success.

**Key Metrics:**
- **Perceived latency reduction:** Immediate visual feedback (avatar + pill visible <200ms) vs waiting for recs (previously 30–60s).
- **Bundle efficiency:** Lottie chunk not included in initial JS (verified via build manifest).
- **Cache hit bonus:** Ticker phrases encourage user engagement while searching (combats perceived slowness).
- **Accessibility compliance:** ARIA labels static per phase, ticker text in `aria-hidden` zones, checklist state changes announced once per phase (not per frame).

**Architecture:**
- `lib/chat/loading-copy.ts` — Pure TS helpers (TICKER_POOLS, CHECKLIST_STEPS, fake quán names, deterministic pickers).
- `components/chat/loading-checklist.tsx` — React component rendering 3-step progression.
- `components/chat/loading-cooking.tsx` — Lazy Lottie wrapper with fallback + reduced-motion support.
- `hooks/use-prefers-reduced-motion.ts` — Shared motion preference hook (SSR-safe, DRY).
- `components/chat/restaurant-card-skeleton.tsx` — Modified to include name flicker overlay with stagger.
- `components/chat/assistant-message.tsx` — Wired all 4 layers (pill with ticker + Lottie + checklist + skeleton with names).

**Code Review Status:**
- No critical issues identified. 3 phases integrated cleanly, all tests pass, no regressions.

**Output:**
- 4 new files: `lib/chat/loading-copy.ts`, `components/chat/loading-checklist.tsx`, `components/chat/loading-cooking.tsx`, `hooks/use-prefers-reduced-motion.ts`.
- 1 new test file: `tests/chat/loading-copy.test.ts` (18 cases).
- 3 modified files: `assistant-message.tsx`, `restaurant-card-skeleton.tsx`, `package.json` (added `@lottiefiles/dotlottie-react`).
- 1 new asset: `public/loading-cooking.lottie` (724B CC0).

---

## Phase 9b: Post-MVP Hardening & Fixes

**Target:** 2026-04-27+ | **Estimated Effort:** 3–4 days (parallel agents)

### 9.1 Critical Bug Fixes (BLOCKER FOR PROD)
Must fix before any public deploy:

**C1: `recs_delta` double-JSON-encoded**
- File: `lib/chat/responses-runner.ts:329`
- Fix: `onEvent("recs_delta", JSON.parse(pass2Text))` to pass object, not string
- Validation: client receives place cards during streaming
- PR: 1 file, <5 LOC change

**C2: Pass-2 uses wrong Responses API shape**
- File: `lib/chat/responses-runner.ts:303–313`
- Fix: Change `response_format: { ... }` to `text: { format: { type: "json_schema", ... } }`
- Validation: structured output returns valid recommendations
- PR: 1 file, ~10 LOC change

**C3: Open redirect on auth callback**
- Files: `app/auth/callback/route.ts`, `app/api/auth/merge-guest/route.ts`
- Fix: Apply `safeNext()` validator to all `next=` redirects
- Validation: Attempting `?next=//evil.com` falls back to `/`
- PR: 2 files, ~5 LOC per file

**C4: Device_id hijack via request body**
- File: `app/api/auth/merge-guest/route.ts`
- Fix: Accept device_id ONLY from HttpOnly cookie, never from request body
- Validation: Merge rejects mismatched or missing device_id cookie
- PR: 1 file, ~10 LOC change

**C5: Admin key default in code**
- File: `lib/env.ts`
- Fix: Remove `.default("dev-admin-key-change-me")` from ADMIN_KEY schema
- Make ADMIN_KEY required; `.min(16)` for production strength
- Validation: Missing ADMIN_KEY in env fails startup
- PR: 1 file, ~5 LOC change

### 9b.2 High-Priority Security & Reliability
Fix before scaling to >100 concurrent users:

**H1: Add AbortController to Nominatim & ipapi fetches**
- Files: `lib/location/nominatim.ts`, `lib/location/ip-geolocate.ts`
- Fix: Wrap with 5s timeout AbortController (match weather.ts pattern)
- Validation: Stalled upstream requests timeout cleanly
- Tests: Mock slow upstream, verify abort

**H2: Hide error details in health endpoint**
- File: `app/api/health/route.ts`
- Fix: Return only `{ ok, supabase: "ok"|"error", redis: "ok"|"error" }`
- Log detail server-side; never expose to client
- Validation: Error message doesn't leak hostnames or URI internals

**H3: Rate limit geocode keyed on IP + session (not client-controlled headers)**
- Files: `app/api/location/search/route.ts`, `app/api/location/reverse/route.ts`
- Fix: Prefer x-forwarded-for (IP) over x-session-id for rate limit key
- Apply two-limit strategy: (IP + session) both must pass
- Tests: Rotating session_id can't bypass IP limit

**H4: Add rate limit to `/api/location/ip`**
- File: `app/api/location/ip/route.ts`
- Fix: Call `ratelimitGeocodeMap.limit(ip)` before ipGeolocate
- Validation: Abusive client hits limit at 1000 calls/day per IP

**H5: Refactor `useFavorites` to Zustand store**
- Files: `hooks/use-favorites.ts`, `components/chat/restaurant-card.tsx`
- Fix: Extract favorites into Zustand store (singleton); cards consume from store
- Remove per-card hook instantiation
- Validation: One fetch for 5 cards instead of 5

**H6: Fix nested button HTML in RestaurantCard**
- File: `components/chat/restaurant-card.tsx:97–149`
- Fix: Convert outer button to `<div role="button" tabIndex={0}>` or restructure
- Validation: No nested button elements; screen reader OK

**H7: Add AbortController to chat SSE fetch** ✅ FIXED (Phase 9a)
- File: `hooks/use-chat-stream.ts`
- Fix: Create AbortController; abort on unmount + on `clear()`
- Validation: Navigating mid-stream closes request cleanly
- Status: DONE (AbortSignal plumbed through orchestrator, client cleanup on unmount)

### 9b.3 Test Coverage (Phase 9b Backlog)
Implement unit tests for untested modules:

**Coverage targets:**
- `lib/chat/responses-runner.ts` — orchestration, event emission, error handling
- `lib/chat/persist-turn.ts` — conversation creation, message/rec insertion
- `lib/chat/load-history.ts` — message fetch with RLS check
- `lib/location/ip-geolocate.ts` — IP lookup + caching
- `lib/auth/resolve-identity.ts` — identity resolution from request

**Effort:** ~3 days (1 agent dedicated to testing)

**Tools:** Vitest, mock Supabase/Redis

### 9b.4 Evaluation Round 1 (Infrastructure Ready)
Once bugs C1–C2 fixed, run evals:

```bash
pnpm dev
node evals/run-evals.mjs --base=http://localhost:3000 --out=evals/results/20260422
```

**Grading:** 30 VI queries × 3 dimensions (grounded, relevance, tone)
**Success criteria:**
- Grounded: 30/30 (100% — no hallucinated place_ids)
- Relevance avg: ≥4.0/5 (27/30 queries score 4+)
- Tone avg: ≥4.0/5 (27/30 queries score 4+)

**If eval fails:** Iterate `persona-prompt-v2.ts` → re-run Round 2

### 9b.5 Performance Tuning
- Monitor P50/P95 latency via usage_log aggregation
- Profile chat API with heavy load (sequential sends)
- Optimize Places rule-filter window (currently top 5 hardcoded)
- Benchmark Supabase RLS overhead (query time before/after merge)

### 9b.6 Documentation Completeness
- Write `docs/codebase-summary.md` (module inventory)
- Write `docs/system-architecture.md` (data model, SSE events, security)
- Write `docs/code-standards.md` (naming, TS, testing, commit format)
- Update `docs/development-roadmap.md` (this file)
- Update `docs/project-changelog.md` with bugs fixed

---

## Phase 10+: Future (Out of Scope MVP)

### Phase 10: Map View (Q3 2026)
- Google Maps embed + place markers
- Click marker → open place details + menu preview
- Swipe/pan to explore neighborhood

### Phase 11: Reservations (Q3 2026)
- Integrate OpenTable / Momo / local booking APIs
- In-app reservation form
- Confirmation + reminder emails

### Phase 12: URL Sharing (Q3 2026)
- Share a recommendation → generate short link
- Link loads pre-filled conversation (read-only)
- Analytics: track clicks + redemptions

### Phase 13: Voice Input (Q4 2026)
- Web Audio API + speech-to-text
- "Hôm nay ăn gì?" voice query
- Accessibility: alternative to text

### Phase 14: Multi-City Support (2027+)
- Switch between VN cities (Hà Nội, Sài Gòn, Đà Nẵng, ...)
- Per-city API keys + budget allocation
- Explicit deferral (too complex for MVP)

---

## Success Metrics

| Metric | Target | Owner | Validation |
|--------|--------|-------|-----------|
| **Grounded recommendations** | 100% | Evals | 30/30 queries return only real place_ids |
| **Relevance (avg)** | ≥4.0/5 | Evals | 27/30 queries score 4+ |
| **Tone (avg)** | ≥4.0/5 | Evals | 27/30 queries score 4+ |
| **TTI (Time-to-First-Byte)** | <2.5s | Monitoring | usage_log P50 latency |
| **P50 chat latency** | <4s | Monitoring | usage_log aggregate |
| **P95 chat latency** | <8s | Monitoring | usage_log aggregate |
| **Places cache hit rate** | ≥60% | Monitoring | usage_log.cache_hits / places_calls |
| **Daily cost (1k turns)** | Places <$40 + OpenAI <$3 | Budget guard | Actual spend tracked |
| **Lighthouse a11y** | ≥95 | Lighthouse CI | Automated on PR |
| **Bug backlog** | 0 critical, <3 high | Code review | All C1–C5 + H1–H7 fixed |

---

## Key Dependencies & Blockers

- **gpt-5-mini availability:** Verified ✅ Phase 1 bootstrap
- **RLS policy correctness:** Integration test required before deploy ✅ Phase 6
- **Nominatim rate-limit policy:** Monitoring configured; Mapbox fallback ready ✅ Phase 8
- **Supabase project quota:** Free tier allows 500k rows; current usage <1k ✓
- **Upstash Redis free tier:** 1GB, concurrent connections TBD (Phase 9 test load)

---

## Unresolved Questions

1. **Binary PWA icons:** Currently using SVG fallback only. Phase 9 or Phase 10?
2. **Guest-to-user merge transaction safety:** Partial failures possible. Add RPC or sweep? See M7 in code review.
3. **Eval grading criteria:** Exact thresholds (e.g., "relevance ≥4 required") or sliding scale? Define in Phase 9.
4. **Multi-model strategy:** Fallback to gpt-4o-mini configured, but cost comparison between gpt-5-mini + gpt-4o needed. Phase 9 analysis.
5. **Scaling limits:** Current architecture handles <1k daily users. What's the hard ceiling (Places quota, Supabase, Vercel)? Phase 9 load testing.

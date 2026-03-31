# Architecture Decision Records (ADRs)
Log every significant technical decision here. Date, decision, rationale, alternatives considered.

---

## 2026-03-12 — Initial Architecture Decisions

### ADR-001: Hybrid Chess Intelligence Architecture
**Decision:** Chess intelligence (analysis, feature extraction, classification) is deterministic code. LLM only handles natural language lesson generation.
**Rationale:** LLMs hallucinate chess analysis. Grounding all facts in Stockfish + verified TypeScript code prevents the #1 failure mode of "AI chess coaching": confidently wrong lessons.
**Rejected alternative:** Pure LLM chess analysis (Lichess tried this — it was inaccurate and users caught it immediately).

### ADR-002: Stockfish WASM in Web Worker
**Decision:** Stockfish runs client-side in a Web Worker via WASM. Never on the main thread.
**Rationale:** Zero server cost for engine analysis. UI never freezes. Scales to infinite users without compute costs.
**Consequence:** Requires COOP/COEP headers in both dev (Vite config) and production (vercel.json).

### ADR-003: Client-Side Chess.com / Lichess API Calls
**Decision:** Game fetching from Chess.com and Lichess is done directly from the browser, not proxied through our backend.
**Rationale:** Both APIs are CORS-enabled for read-only endpoints. Client-side calls mean no server rate limiting — each user's browser has its own limit. Zero server cost for game fetching.
**How Chessigma does it:** Same approach — direct browser requests to Chess.com's public API.

### ADR-004: No Redis for MVP
**Decision:** Use in-memory LRU cache (cachetools) for LLM response caching. No Redis.
**Rationale:** Redis adds operational complexity and a failure point. In-memory LRU is sufficient until we have meaningful traffic. Cache resets on server restart — acceptable for MVP.
**Upgrade path:** Swap `cachetools.LRUCache` for Upstash Redis client. Single service change, rest of codebase unchanged.

### ADR-005: Neon for PostgreSQL
**Decision:** Use Neon serverless PostgreSQL. Migrated from Supabase (2026-03-27).
**Original rationale:** No Docker, no database admin, free dev tier.
**Migration rationale:** Neon offers serverless auto-scaling, branching for dev/preview, and a more generous free tier. Supabase was only used as a plain Postgres host — no SDK features were in use, making the migration a connection string swap.
**Upgrade path:** Neon Pro ($19/mo) if we exceed free tier limits.

### ADR-006: Vercel (Frontend) + Railway (Backend)
**Decision:** Frontend on Vercel, backend on Railway.
**Rationale:** Vercel: zero-config for Vite/React, global CDN, free tier handles 1000+ daily visits. Railway: simple Python/FastAPI hosting, auto-deploy from GitHub, $5/mo hobby plan.
**Accounts:** Personal accounts (not org) — transfer to org later if project grows to a team.

### ADR-007: Closed Source
**Decision:** Private GitHub repo. All Rights Reserved. No license file.
**Rationale:** The coaching prompts, principle classifier, and LLM pipeline are the product moat. Making these open would hand competitors the differentiator.
**Future plan:** Open-source the non-proprietary parts (board rendering, Stockfish integration, game import) in 6-12 months if/when it makes sense. Use AGPL for those parts (Lichess model).

### ADR-008: Confidence Scoring for Principle Classification
**Decision:** Principle classifier outputs a confidence score 0-100. High confidence (70+) → full principle lesson. Low confidence (<70) → simplified observation-based lesson.
**Rationale:** A confidently-worded lesson about the wrong principle is worse than no lesson. The confidence fallback protects against teaching incorrect concepts. This is the key difference between DeepMove and a wrapper that generates convincing but wrong coaching.

### ADR-009: CLASSIFIER PRIORITY QUEUE
**Decision:** TACTICAL_01 (Blunder Check) and TACTICAL_02 (Ignored Threat) suppress ALL other principle classifications at a critical moment.
**Rationale:** From GM Studer's "Leaky Roof" concept. A hanging piece is always the most urgent lesson — never also mention pawn structure. One lesson, the most urgent one.

### ADR-010: Test Feature Extractors Before Wiring to LLM
**Decision:** Build and validate all feature extractors with comprehensive unit tests BEFORE connecting the coaching pipeline.
**Rationale:** Wrong features → wrong classification → wrong LLM lesson → user learns incorrect chess. The test-first approach for chess logic prevents this cascade failure. Tests are written before features (not after).

---

## Implemented Features

### ADR-011: Move Annotations — Blunder/Inaccuracy/Good/Great/Brilliant
**Status:** Implemented (Track A)
**Decision:** Classify each move by comparing eval before and after the move (from the perspective of the side that moved). Render colored grade badge next to each move in MoveList.
**Actual thresholds (centipawns):**
- Best — ≤10cp loss
- Excellent — ≤30cp loss
- Good — ≤100cp loss
- Inaccuracy — ≤200cp loss
- Mistake — ≤400cp loss
- Blunder — >400cp loss
**Implementation:** `classifyMove()` in `engine/analysis.ts`. Grade badges rendered in `components/Board/MoveList.tsx`.

### ADR-012: Best Move Arrows + Multi-PV
**Status:** Implemented (Track A)
**Decision:** After analysis, overlay arrows on the board showing the engine's top moves for the current position.
**Implementation:** Multi-PV arrows via chessground `autoShapes` (green=best, paleBlue=2nd, yellow=3rd). BestLines panel above move list — click to enter variation mode (arrow keys step through PV, Esc exits). Position analysis triggered after full-game analysis completes.

### ADR-013: Move Grading System Research — Expected Points vs. Centipawn Loss
**Status:** Research complete (2026-03-22)

#### Chess.com CAPS2
Uses an **Expected Points** model based on win probability, not raw centipawns. Each move is graded by how much expected value (0.0–1.0) was lost. Thresholds are adjusted by player rating.
- Best ≤0.00, Excellent ≤0.02, Good ≤0.05, Inaccuracy ≤0.10, Mistake ≤0.20, Blunder >0.20
- Formula is proprietary and not publicly disclosed.

#### Lichess Accuracy
Open-source win% formula: `50 + 50 * (2 / (1 + exp(-0.00368208 * cp)) - 1)`
Per-move accuracy: `103.1668 * exp(-0.04354 * delta) - 3.1669`
Uses harmonic mean to heavily penalize blunders. DeepMove already implements this formula in `cpToWinPct` + `computeAccuracy` in `engine/analysis.ts`.

#### Chessigma
Uses custom labels (Sigma, Awesome, Best, Nice, Ok, Theoretical, Strange, Bad, Clown). Unknown thresholds, centipawn-based. Depth 14 for most positions.

#### DeepMove Current Approach
Raw centipawn-loss thresholds (ADR-011). Transparent and debuggable. 90% of the value of Expected Points for MVP.

**Upgrade path:** The Lichess logistic function (`cpToWinPct`) is already in `analysis.ts`. To adopt chess.com-style grading, swap `classifyMove()` to use win-probability delta (winBefore - winAfter) instead of raw cp loss, then tune per-Elo threshold tables. Defer to post-MVP.

**Open-source reference:** [Chesskit by GuillaumeSD](https://github.com/GuillaumeSD/Chesskit) — similar architecture, useful for comparison.

### ADR-014: Background Tab Analysis — No Special Handling Needed
**Status:** Verified (2026-03-22)

**Decision:** No keepalive or visibility API handling required for Stockfish background analysis.

**Reason:** Web Workers using `postMessage` are not subject to browser background throttling. Only `setTimeout`/`setInterval`/`requestAnimationFrame` are throttled in background tabs. The entire analysis pipeline in DeepMove uses pure `postMessage` UCI communication with zero timers in the analysis loop (the only timer is a one-time 60s init safety timeout in `stockfish.ts`). Analysis will continue at full speed regardless of tab visibility.

### ADR-015: Analysis-First Coaching Pipeline — 6 Categories Replace 19 Principles
**Status:** Implemented (2026-03-31)

**Decision:** Replace the principle-first coaching model (19 taxonomy principles + confidence gates) with an analysis-first model using 6 mistake categories derived directly from feature extraction output.

**Categories:** `hung_piece` · `ignored_threat` · `missed_tactic` · `aimless_move` · `didnt_develop` · `didnt_castle`

**Key changes:**
- `determineCategory()` in `classifier.ts` maps features → category (no principle lookup required)
- `buildAnalysisFacts()` builds 5 deterministic fact sentences fed to the LLM — the LLM never guesses at position details
- `hadClearPurpose` in `moveImpact.ts` widened: pawn moves, rook moves, and centralizing moves are never `aimless_move`
- Sacrifice guard in `determineCategory`: if `futureUserScores` recovers >+50cp within 3 half-moves, suppress `hung_piece` (deliberate sacrifice)

**Rationale:** The 19-principle model required the classifier to be confident about subtle strategic concepts it couldn't reliably detect. The 6-category model only labels things the feature extractor can verify directly (e.g. "piece is literally hanging" → `hung_piece`). This eliminates wrong-concept lessons at the cost of some granularity — acceptable for MVP.

### ADR-016: Coach Tab Layout — MoveCoachComment Above Shared MoveList
**Status:** Implemented (2026-03-31)

**Decision:** Coach tab = eval display + `MoveCoachComment` box (where the graph was) + `MoveList`. Analysis tab = unchanged (eval display + BestLines + EvalGraph + MoveList). Both tabs share the same `MoveList` component and `currentMoveIndex` state.

**Rationale:** Avoids building a parallel transcript component. The MoveList already handles variations, grades, and navigation correctly. The only addition to the Coach tab is the `MoveCoachComment` box which updates reactively as `currentMoveIndex` changes — zero new navigation logic required.

**Removed:** `CoachPanel.tsx` (replaced by `MoveCoachComment` + `MoveList` directly). `GameTranscript.tsx` was built then deleted in the same session — the MoveList approach was simpler and already existed.

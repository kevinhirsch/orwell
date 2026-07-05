# CLAUDE.md

This file provides guidance to Claude Code (claude.ai/code) when working with code in this repository.

> **Overseer continuity:** if you are orchestrating this work as an *overseer* (dispatching delegate
> agents, reviewing, watching CI, merging), read [`SOUL.md`](SOUL.md) first — it holds the operating
> model, dispatch discipline, the hard-won lessons (diagnose-before-revert, live-verify streaming
> changes, the `stat -L` agent-health rule, the gitignored-`settings.json` test red herring), and a
> current-state snapshot. It is operational continuity, distinct from the game's `CHARACTER`/`SOUL`.

## What this project is

`orwell` is a rebuild of an immersive, single-player, text-based **_Big Brother_ simulation**
as a web application. The system is game master, narrator, and the voice of every NPC
houseguest. A prior version ran entirely inside one LLM chat context; this rebuild moves
game state into **external, permissioned stores** behind a **hexagonal architecture** so
that the deterministic rules, the secret state, and the narration are cleanly separated.

**Status: feature-complete through the drafted spec set (BDD/TDD-first; reconciled 2026-06-23).** Specs now run
through **0110**, and the originally-drafted set is built and **green** — but the spec ceiling now runs ahead of the
*built* one: **0075–0093, 0099–0100, 0102, 0104–0107, 0109, 0110** are built, while **0094–0098, 0101, 0103**
remain **spec-only/frozen** (the Producer's-Vault audit + PO-review batch — some parked, some awaiting a
build slot; 0102 shipped 2026-07-05 as the redesigned daily recap, #884) and **0108** is spec-only (the
real-model golden-path gate). *(The former lone deferral, **0022
(MVP-2, the rich game UI)**, was **removed** in the 2026-06-28 PO review — superseded by 0020/0051/0054
under ADR 0003.)* The
reconciled per-feature index in `docs/features/README.md` is authoritative for built vs. spec-only — plus **0053**
(admin transcripts, FE-side) — covering: the eight
priority invariants, the MCP seam, the one-liner deploy, the gameplay loop, the MVP-1 batch —
including the **living, persisted consequence loop (0023)** (act → hidden impact → persist →
recall, wired into the live game) — the live-loop batch, the endgame batch (Final 5 → Final 2,
player eviction & the juror's seat, eviction night live), the post-audit batch (0038 live
society + gossip diffusion, 0039 deals, 0040 confessionals, **0041 character evolution — the
linchpin**, 0042 competition library, 0043 emergent blocs, 0044 strategic noms/votes), 0048
retrospective/unsealing, 0049 house presence & lingering, and 0050 the casting interview.
**Every batch in `docs/IMPLEMENTATION_QUEUE.md` is ✅ DONE** (each item carries its verifying
artifact) — through the B/C audit waves (B34–B73 / C12–C33), the round-4 UI & runtime audit
(D1–D11), the round-5/6 full-product-audit campaign (the E/P/W/S/T parallel lanes + the
prioritized UI track U1–U5), and the 2026-06-11 close-out lanes (cross-lane tails, the
T-remainder, 0053, E86a fastembed). The **campaign close-out ledger** in
`docs/audits/2026-06-10-full-product-audit.md` is **the authoritative open-items list going
forward**. *(2026-06-11, post-ledger: the **DWE windowing lane** — Lane F — shipped end to end:
the window audit (`docs/audits/2026-06-11-dwe-window-audit.md`), the `OrwellWindow` kit +
`.ow-*` family, the migration waves, and the F-3 anti-fragmentation ratchet; new FE windows
MUST compose the kit.)* The game is **folded into the main chat**: the player-facing tier is the vendored
**Orwell** front-end (`frontend/`, Python) talking to the TS engine over MCP (see
[Architecture](#architecture-hexagonal)). Priority-ordered feature specs live in
`docs/features/` (through **0110**; the 0067–0074 launch band is 0067/0068 public-internet exposure + ADR 0007, 0069 token economy,
0070 off-screen texture enrichment, 0071 defensive hardening (redaction + URL/path guards), 0072 the
multi-platform gateway, 0073 the structural anti-sycophancy game-build wall (a CI gate), and 0074 local &
tunable HTTPS (ADR 0014); past the launch band, **0075–0093, 0099–0100, 0102, 0104–0107, 0109, 0110** are built and **0094–0098, 0101, 0103** remain spec-only/frozen (Producer's-Vault/PO-review batch) with **0108** spec-only;
0052 — the house themes — shipped FE-side from the audit
spec with no standalone file; 0051 in-character images shipped 2026-06-11, PR #235, and its
follow-on **portrait/headshot lane** — Lane G — extended it FE-side: cast-portrait generation &
backfill, the casting headshot studio + player-uploaded/AI account avatar, portrait variety, and
the game-build provider gating (OpenRouter image models via `/chat/completions`)). **New work starts as a new spec/queue
item** — the remaining known deferrals are listed under [Current status](#current-status); the
governing design rulings are `docs/audits/2026-06-09-product-audit.md` ("Remediation
principles"), the **product-owner rulings #1–#21** in `docs/audits/2026-06-10-full-product-audit.md`,
and ADRs `docs/decisions/0003` (the conversation is the game) and `docs/decisions/0005` (split
authority by openness — the engine records the open set of social play, never normalizes it).

## Source of truth — read these first

The design is fully specified. **Read `docs/CLAUDE_CODE_INSTRUCTIONS.md` first** (the build
brief and complete decision log), then `docs/bb-sim-spec.md` (the v3 domain spec). These two
are authoritative and reference each other as companions.

| File | Role |
|---|---|
| `docs/CLAUDE_CODE_INSTRUCTIONS.md` | **Build brief & decision log** — start here. Architecture directives, workflow, hard "do-nots", milestones, open decisions (§15). |
| `docs/bb-sim-spec.md` | **v3 domain spec** — concept, persistence model, Vault Wall, behavioral-fidelity mandate, the BDD invariants (§12), open decisions (§16). |
| `docs/decisions/` | **Decision records (ADRs 0001–0016)** — accepted refinements to the canonical mechanics. 0001 competition stats / Character-Soul split / veto "Houseguest's Choice" · 0002 organic relationship model · 0003 the conversation is the game · 0004 embedding provider (fastembed/ONNX) · 0005 split authority by openness · 0006 in-game time/sleep/presence economy · 0007 public-internet exposure · 0008 cross-tab/-device chat consistency · 0009 location/movement single source of truth · 0010 token-economy architecture · 0011 concurrent engine-drive beat-aware guardrails · 0012 two-window lockstep "Messenger mirror" · 0013 cast photos require a model-authored identity · 0014 local & tunable HTTPS (LAN-trusted, with or without a domain) · 0015 collapse the duplicated live-vs-mirror chat render paths (ship-gate F5's root cause) · 0016 LLM model selection (GLM-4.7 narrator/utility, Seedream portraits — the currently-live default). (`README.md` there indexes them.) |
| `docs/features/` | **Priority-ordered feature specs** — each `NNNN-*.md` (design note) + `NNNN-*.feature` (executable Gherkin), built in order. `README.md` there holds the live per-feature **status index** and the **Amendments to shipped specs** table (implementers must pick those up). |
| `docs/IMPLEMENTATION_QUEUE.md` | **Live work queue** — per-item implementation prompts (B/C/D/U/L-numbered lanes), dispatch order + dependencies, and the truest prose snapshot of what's done vs. remaining. |
| `docs/audits/` | **Audit record & rulings.** `2026-06-10-full-product-audit.md` carries the product-owner **rulings #1–#21** and the **campaign close-out ledger** (the authoritative open-items list); `2026-06-10-v1-transcript-meta-feedback-audit.md` reconstructs the v1 game from its logged transcripts (why the Bible's emphatic passages exist). The 2026-06-11 **house-audit pattern** (real FE + real engine driven headless under Playwright, DOC-ONLY) produced `2026-06-11-dwe-window-audit.md` (windowing), `2026-06-11-refresh-persistence-audit.md` (every transient UI state × reload), and `2026-06-11-settings-wiring-audit.md` (every settings control × {wired, persisted, applied}). The **`2026-06-27-ship-gate.md`** is the **launch-acceptance bar** — the authoritative "what blocks ship": the FE-airtight standard **F1–F5** (no missing messages, right status, smart queueing, multi-window concurrency, realtime two-window mirror parity — the #1 release blocker) and the casting→eviction golden path **G1–G9**, each with the real-model gate that proves it, plus the launch-blocker / post-launch / parked triage of every open issue. |
| `docs/legacy/BB_GameBible.md` | **Legacy reference only.** The old chat-prompt implementation being replaced. Source of the *concrete* mechanics, but its fixed player persona / names are illustrative — never hard-code them. Same rule for the vendored v1 transcripts in `docs/legacy/meta-feedback/`. |

## The non-negotiable mandate

These four priorities override convenience. A mechanically-correct but behaviorally-thin or
leak-prone build is a **failure state**, not a partial success.

1. **Behavioral fidelity is priority #1.** Reproduce the *full social texture* of a real
   _BB_ episode — drama, nuance, hidden conversations, and **off-screen NPC-to-NPC scheming
   the player never witnesses**. Tests must verify *richness*, not just mechanics.
2. **The Vault Wall is absolute and structural.** Secret state can never reach the player —
   enforced in code at the port/tool boundary, *never* by prompt wording. The model "cannot
   leak what it never receives." **God Mode / admin is walled from the Vault too** (the human
   has never read it and must not be able to — spoilers ruin the game above all else).
   **The ONE sanctioned exception (owner-ruled DEBUG override): `producerVault`** — a live-Vault
   *unseal* for operator debugging. It is deliberately quarantined and is NOT a hole in the wall for
   normal play: it lives in `DEBUG_VAULT_TOOLS` (the *only* `readsVault: true` registry — the literal
   `ToolDescriptor.readsVault: false` guard still holds for every advertised tool), is **out-of-band**
   (never in the `toolsFor` allowlist), **admin/God-Mode channel only**, and fires **only** behind an
   explicit FE "unseal" on `/admin/status` (hidden by default). Every "admin allowlist is Vault-free"
   guarantee stays literally true; `tests/unit/producerVault.test.ts` is the gate. Do **not** "fix" it
   as a leak — it is intentional; do **not** widen it (never the player channel, never an advertised
   tool, never always-on).
3. **Anti-sycophancy.** The deterministic core + seeded randomness decide outcomes; the LLM
   only *narrates*. Ground truth lives in the stores and is *queried*, never "remembered"
   and bent to please the player.
4. **Non-degradation.** Persisted detail must **never** be lost across saves and should
   *accumulate and deepen* over a game. The old version's secret store thinned out over time;
   do the exact opposite.

**The conversation is the game (`docs/decisions/0003`).** The beta proved the loop — a good LLM +
the Bible + secrets *is* the game. The engine exists only to fix the four degradations above
(leaks / sycophancy / memory-thinning / sameness) and otherwise **get out of the model's way**:
prefer removing context to adding it; hand the model *facts to voice*, never *scripts to recite*;
UI may **augment** the chat intelligently but never **replace** an interaction that builds or
progresses the game; **lingering is play** (the player can mill around any room, learn who's
present/adjacent, and talk to anyone — while those NPCs keep playing *their* game, and nothing
force-marches the week); **people must make sense** (one place at a time; speech scoped to what
each NPC legitimately knows; stable public persona); replayability is engine-seeded, and
long-term memory is the store *recalled*, never the chat *remembered*. Each of these is
**testable structurally** where possible (see the ADR's testability section). Don't "improve"
the game into a dashboard.

## Architecture (hexagonal)

Keep the **domain core pure and dependency-free** (no I/O) regardless of stack choices.
Everything else sits behind ports.

- **Domain core** — the Game Bible as code: the weekly loop (HOH → nominations → veto →
  veto ceremony → eviction → jury → final two), eligibility/legality rules,
  **stat-+-temperature-weighted** competition resolution, votes, win conditions, and the
  daily-event invariant. Fully unit-testable with a seeded `RandomnessSource`.
- **Ports (interfaces)** — at minimum: `GameStateRepository`, `VaultStore` (**engine-only**),
  `JournalStore`, `EventStore`, `KnowledgeService`, `NarrativePort` (the LLM),
  `RandomnessSource` (**seedable**), `Clock`/`Scheduler`, `CharacterFactory`, `SoulProvider`.
- **Adapters** — DB adapter(s) for relational/graph state and the event record; soul storage
  (md and/or vector); **MCP server(s)** exposing *permissioned* tools to the narrative LLM
  (e.g. `getVisibleStateFor(entity)`, `recordInteraction`, `resolveCompetition`,
  `surfaceInformationTo(player, fact, pathway)`); the LLM adapter behind `NarrativePort`.

**The permission boundary is the whole point.** No player-facing **or** admin/God-Mode-facing
adapter or tool may depend on `VaultStore`. A surface is not "done" until a test proves it
returns no Vault data.

### Three channels → ports

- **Administrator / God Mode** — admin-only meta port (configure, override mechanics, inspect
  **non-Vault** state, manage the sandbox). Walled from the Vault even for the admin.
- **Player-level** — out-of-character strategy/directives within the player's agency.
- **In-character** — narrative interactions.

Each running game is its own isolated sandbox — keyed to the **physical-world user**: **one
active game per user**, **unlimited users concurrently**, each fully isolated. **Cross-user
isolation** is a first-class guarantee *alongside* the Vault Wall (no call for user A may return
user B's game — secret or not). The chat is each user's window into *their* game. (Feature 0021.)

### Wiring an FE-driven engine write-back (the recurring boundary gotcha)

Several engine tools are **FE-driven write-backs**: the front-end (which owns a concrete provider —
an LLM, `web_search`, the image API) produces content and writes it BACK so the **engine** stays the
source of truth. The live ones: `recordCastProfile` (0058 deep-profile authoring), `preSeedCast`
(0065 cast pre-warm), `recordWorldSnapshot` (0062 zeitgeist), `recordImageBeat` (0051). Adding one is
a **four-place** change, and a missing piece fails **silently at runtime** (the FE call is rejected at
the MCP boundary, and the best-effort caller swallows it):

1. `src/ports/GameSession.ts` — the method + its req/result types.
2. `src/adapters/engine/GameSessionAdapter.ts` — the implementation.
3. `src/surfaces/tools/registry.ts` — add to `PLAYER_TOOLS` **and** to `INFRA_LEVERS` (these are
   FE-driven, **not** model levers, so they stay out of the agent's lever manifest / drift gate).
4. `src/adapters/mcp/McpServer.ts` — a `requireShape` arg-guard case **and** a `callTool` dispatch
   case (+ the type import). A *pre-game* tool also goes in `HttpMcpServer`'s `SANDBOX_CREATING_TOOLS`.

**The static gates do NOT catch a missing #4** — dependency-cruiser only checks Vault edges, the
lever-manifest drift test only checks prose — so a write-back with steps 1–2 done but 3–4 missing
typechecks, passes `test:arch` + the manifest test, and is **dead at runtime**. `recordCastProfile`
and `recordWorldSnapshot` both shipped exactly this way and silently no-op'd for a long time. The fix
is a **boundary test that dispatches the tool through `McpServer.callTool`** for every write-back
(`tests/unit/castPrewarm.test.ts`, `tests/unit/worldSnapshotBoundary.test.ts` are the templates).

The FE driver is a best-effort, **idempotent, fail-soft background task** in `frontend/src/`
(`orwell_cast_authoring.py`, `orwell_prewarm.py`, `orwell_zeitgeist.py` — each: resolve a utility LLM
via `_resolve_llm_fn`, optionally `web_search`, synthesize JSON, write back; **no model/provider ⇒ the
engine's deterministic floor simply stands**). Kicked from `do_create_character`
(`tool_implementations.py`); never blocks game start.

## The event / visibility model (build this carefully — it caused real bugs before)

There is **one `EventStore`** holding every interaction. **Visibility is per-event metadata —
a witness set + a hidden flag — not a function of which store the data lives in.**

- **Player-witnessed = not secret.** If the player is in an event's witness set, it is the
  player's knowledge (Journal-visible). Do **not** mislabel witnessed events as off-screen/
  secret — that was a concrete past bug where the Vault wrongly logged events the player was
  present for.
- **The Vault holds only genuinely off-screen/hidden content** — NPC-to-NPC scenes whose
  witness set excludes the player, plus hidden attributes and confessionals.
- **Propagation only via in-game pathways.** A hidden fact reaches the player only when an NPC
  tells them, they overhear, etc. — modeled explicitly in `KnowledgeService`. The Vault Wall
  stays intact because surfacing is an explicit, traceable event. A houseguest can only know
  what they witnessed or were told; if there's no pathway, they don't know it (they may
  *suspect*, but cannot *know*). Hidden facts also **diffuse NPC-to-NPC along the social graph**
  (gossip), drifting with each retelling, so what reaches the player can be a distorted belief
  held with a source + confidence — diffusion runs in the hidden layer and only updates the
  player's knowledge when a pathway terminates at the player (ties to `docs/decisions/0002`).
- **Diary Room / confessionals are events too.** NPC confessionals are Vault-only content
  (off-screen, witness set excludes the player). The player's Diary Room is a *player-level,
  OOC* channel: its content is the **player's own knowledge** but has **no in-game pathway to
  any NPC** — it may inform the engine's read of player strategy, **never** NPC behavior. (DR
  mechanics are concrete in the legacy Bible §6–§7; the provisional domain model is spec §11.)

## The consequence & memory loop (the MVP-1 backbone — feature 0023)

Recording an event is only half the loop. Every happening — a conversation, a competition win, a
vote, a scheme — must also **fold its hidden impact into the relationship/soul layer** and
**persist**:

```
happening → recorded event (witness set + hidden flag)
          → engine applies its HIDDEN impact to the relationship/soul layer
            (trust/affinity/threat move — the player's action changes how they feel about them)
          → persisted to long-term memory: every event detail + the derived hidden state
          → recalled in full on return / restart — the house still remembers.
```

The opinion change lives in the **hidden layer** (Soul/Vault) — the player **never sees the
numbers**, only the later behavior. That is the Vault Wall working: the change is real, recorded,
and invisible. **This is the point of the game.** It is now **green** (feature 0023): the live
game wires events (0002), relationships (0017/0026), and persistence (0007/0030) together —
the **live** folds happen in the adapters: `EngineCommandsAdapter.recordInteraction` records the
event and folds its hidden impact, and `GameSessionAdapter` folds ceremony beats
(`foldCeremonyConsequence`) and soul evolution (`evolveFromBeat`); `src/engine/consequence.ts` is
the older 0023 module (off-screen-sim path). The orchestrator (`src/composition/orchestrator.ts`)
persists each turn with a fail-closed integrity checkpoint (0031). Hold the line that made it
work: **never ship an action that is narrated but never recorded** — it has no consequence and no
memory.

**The front-end error-corrects the model (`frontend/src/agent_loop.py`).** A real, recurring gap:
the narration LLM reliably **under-calls** the engine tools — it won't `advanceGame` (the game
freezes at a beat) and won't `recordInteraction` for the player's social scenes (they fold zero
impact). The engine is fine; the *model* skips the call. So the FE agent loop carries two in-loop
guardrails (the owner's ruling: keep the dynamic DM, error-correct the omission — never engine-
author content): (1) a **progression stall-nudge** that, when the live game sits in an advance-
phase and the player turn is a *lull* (engagement-driven, never a turn count — pacing is "seize the
lull, let substantive play run"), nudges the model to `advanceGame`; and (2) **`_auto_record_scene`
(feature 0055)** — when an engaged player↔houseguest turn recorded nothing, the FE makes a
constrained extraction call (`{withIds, kind, content}`, model-proposed direction) and calls
`recordInteraction` itself, GUARANTEEING the social play moves the hidden weights. Model-driven
recording always takes precedence. When debugging "the game won't advance" or "social play has no
consequence," look here, not only at the engine. The **same under-call bites the game-start and premiere
seams**, error-corrected by the same family (audit 2026-06-20): the casting framing (`apply_game_framing`
in `routes/chat_helpers.py`) tells the model the **headshot is already on file** so it stops re-asking and
finalizes; a **`createCharacter` finalize fallback** starts the season when casting is engine-`ready` and
the player signals readiness; the advance stall-nudge **escalates to a forced `advanceGame` (L39b)** when
the model ignores every rung; and a **premiere `markHouseguestMet` auto-belt** keeps the #380
meet-everyone gate progressing. These guardrails fire only where the model SKIPS a call — the engine is
fine; never engine-author content.

**Sync work must never flatten creative play (`docs/decisions/0005`).** Authority splits by
*openness*, not by *layer*: the **closed set** (outcomes, eligibility, state truth, persistence,
the Vault) is engine-dictated — *no dynamism to lose* — while the **open set** (the meaning/texture
of social play) is recorded faithfully and **never normalized** into a closed bucket in a way that
changes what can be narrated or played next. Concretely (PR #355): `recordInteraction` / the 0023
`ConsequenceEngine` take an optional, Vault-free `consequence` descriptor — the model proposes the
*shape* (which edge moves, which direction, relative `emphasis`); the engine keeps the bounded,
seeded *magnitude* (no raw number crosses; `kind` is the floor, so no descriptor ⇒ byte-identical
fold). `tests/unit/expressiveNonCollapse.test.ts` + `frontend/tests/test_expressive_non_collapse.py`
are the permanent gate, and the FE desync guard may fire only on closed-set board claims, never on
creative prose.

**The closed-set sync spine (feature 0065) hardens the above.** ADR 0005's closed-set counterpart:
the engine issues a monotonic **`beatSeq`** on every read/advance (owned by `GameSessionAdapter`,
bumped once per committed mutation in the registry commit funnel, persisted in the snapshot). Mutating
tools take an optional **`expectedBeatSeq`** (stale ⇒ typed `StaleBeatError` → HTTP **409 `stale-beat`**,
refused *before* any write) and **`idempotencyKey`** (at-most-once progression). The FE holds last-seen
`beatSeq` per canonical session, attaches it, refreshes from every response (no self-409s), and
reconciles a 409 through the existing desync mechanism. A **pre-emission outcome guard** corrects a
phantom board claim *before* the player sees it (closed-set claims only — `chat_helpers.py`); a Vault-free
per-turn **divergence ledger** (`frontend/src/orwell_sync_ledger.py`) records the sync activity; and a
`beatSeq`-keyed **`stateDelta`** read feeds the model a tight O(Δ) "what changed since your last turn"
delta. Every part is opt-in/back-compatible (absent field ⇒ byte-identical) and closed-set only — it
never touches creative prose (the `expressiveNonCollapse` gates stay the proof).

## Front-end client conventions (non-obvious — verify before editing `frontend/static/js/`)

The sections above govern the engine/closed set; these are the **player-tier client** conventions
that span several JS files, aren't captured elsewhere, and have each caused a real regression. Read
them before touching the chat stream or the HUD.

- **`orwell:gamechanged` has exactly ONE dispatcher (the g15 freshness seam).** The HUD/sidebar
  panels are poll-based (20–30s) and stay fresh by *listening* for the debounced `orwell:gamechanged`
  window event whose **only** dispatcher is `orwellGameChanged(reason)` in
  `frontend/static/js/platform.js` (~250ms trailing debounce, also `window`-exposed). Every FE
  mutation seam **calls that helper** — the chat tool-result seam (each game-mutating tool) and the
  decision-card POST success — and **nothing** may `new CustomEvent('orwell:gamechanged')` ad-hoc.
  `frontend/tests/test_g15_gamechanged.py` enforces "exactly one dispatcher" + that every mutating
  tool routes through it. Cross-**device** reconcile is a *separate* seam: `_publish_game_updated`
  (feature 0064, server-push) in `frontend/routes/orwell_routes.py`. Wiring a new mutation? Call the
  helper; don't add a poll or an ad-hoc dispatch.

- **Two-window realtime parity rides on a LIVE canonical-session binding (ADR 0008/0012).** Two
  windows on one game mirror each other only when the *canonical game-session id*
  (`GET /api/orwell/game-session`, stored in `frontend/src/orwell_game_session.py`) resolves to a
  **live FE chat-session row**: the persistent mirror stream `GET /api/chat/events/{id}` + resume
  `GET /api/chat/resume/{id}` both 404 a non-row id, and `_resolve_canonical_session`
  (`routes/chat_helpers.py`) is the server run-key. Convergence is gated on `started !== false` — a
  started game mirrors; casting stays per-tab by design. Two regressions to never reintroduce (both
  fixed): a session-delete that doesn't **unbind** the canonical id leaves the mirror subscribed to a
  dead channel and *collapses the window* (#1085), and resolving the canonical id during casting
  causes a settle-time session switch that *strips the just-streamed reply* (#1086). Always validate
  the binding resolves live before subscribing, and unbind on delete. The multi-window airtight bar
  (F1–F5) is the authoritative gate: `docs/audits/2026-06-27-ship-gate.md`.

- **The live stream splits by channel — reasoning must NEVER reach the public bubble.** In
  `frontend/static/js/chat.js` the streaming loop keeps two per-round buffers: `roundReplyText`
  (deltas with `json.thinking` falsy) and `roundReasoningText` (truthy). The message **body** renders
  ONLY `roundReplyText` through `markdown.js processWithThinking` (which, in the game build, also
  scrubs operator-aside / raw `npc:<id>` leaks); the live **"Thinking" accordion** renders
  `roundReasoningText`. Reasoning is kept out of the body *by construction* — do not reintroduce
  regex extraction of the reply from a merged buffer. Reset both buffers in lockstep with `roundText`
  (at `agent_step` / `teacher_takeover`); the merged `roundText` / `accumulated` stay intact for the
  other consumers (doc-fence, TTS, persistence `dataset.raw`, background streams, `<think time=…>`).
  The **stall watchdog (`_startStallWatchdog`) is deliberately DISABLED** — the server-side stall
  detector + auto-continue loop-breaker supersede the old "still working?" banner; don't re-enable it.

- **Run the WHOLE FE suite before pushing FE changes.** `cd frontend && python3 -m pytest tests/`
  (venv at `frontend/.venv`). Many gates are source-pinned convention checks (g15, the reasoning
  scrub, the render contract) that live outside obvious keywords — a `-k` subset can pass green while
  the real gate fails (the CI `frontend` job runs the full suite).

## Characters, souls & per-moment temperature

- **Only the player's profile is human-authored** (first-run OOBE). **All NPC profiles are
  generated** by `CharacterFactory`, constrained to plausible _BB_ contestant archetypes
  (internally consistent, reality-TV-plausible). Generate **tons of hidden elements** per
  character; public persona may match or wildly diverge from hidden attributes; hidden
  elements surface **rarely** (gated by the temperature roll) and profiles **evolve** as the
  game proceeds. Souls may be md and/or vector-backed.
- **Static `CHARACTER` vs dynamic `SOUL`.** A houseguest's stable baseline (archetype, core
  competition aptitudes, identity, backstory, baseline temperament) is **static `CHARACTER`**
  ("facts"); evolving state — current **emotional** state, accumulated memory, leanings, and
  **relationship beliefs** — is the **dynamic `SOUL`** (md + vector). Relationships are **not**
  binary ally/enemy flags: they are directed, graded, asymmetric, uncertain beliefs
  (trust/affinity/threat…) computed from event history, and any "ally / best-friend / enemy"
  label is **organic and emergent** — read through the holder's own character framing, never
  stored (`docs/decisions/0002`). The competition **emotional modifier** (a baseline that grows
  more or less volatile with circumstances + temperature) and the veto "Houseguest's Choice"
  both read the dynamic soul. See `docs/decisions/`.
- **The player forms their own reads (human-driven).** The engine computes both `NPC→player` and
  `player→NPC` relationship edges from history — but **never shows the player a number** and never
  asserts how they feel ("you trust them"). Player-facing surfaces show **facts the player knows +
  observable houseguest behavior**; the player **infers** trust and threat themselves. Paranoia and
  loyalty are the human's to form (features 0017/0020/0023). The model is computed and hidden; the
  *feeling* is theirs.
- **Temperature is per-moment, not a global knob.** Each gameplay moment rolls temperature
  across *all* involved variables (outcomes, expression, NPC initiative, which secret
  surfaces, alliance shifts, volatility…). It governs variance/surprise but **never** overrides
  hard rules (eligibility, the Vault Wall) or archetype-grounded outcome weighting. Drive it
  through the seedable `RandomnessSource` so distributions are testable.
- **Bidirectional scenes.** NPCs hold goals from their profiles that make them approach the
  player, *and* the player can initiate. Neither side initiates everything.

## Canonical game mechanics (from the legacy Game Bible — still authoritative)

- **Cast:** 16 houseguests (player + 15 NPCs). **Jury of 9. Final 2.** Classic format, no
  core-structure twists (one or two production twists may be held in reserve).
- **A "week" = one HOH reign** (HOH comp → eviction), not seven calendar days.
- **Veto competition:** **six** players — the HOH, the two nominees, and **three by chip
  draw**. One chip is **"Houseguest's Choice"**: whoever draws it picks the sixth player
  instead of a random name (NPCs choose by soul motivation — their strongest available bond
  per the relationship model, `docs/decisions/0002`). The player can't influence which chips
  are drawn, but may hold Houseguest's Choice if drawn.
- **Eligibility/legality (hard rules):** the **outgoing HOH cannot play** for the next HOH;
  the **veto winner cannot be named replacement nominee**; all houseguests except the HOH and
  the two nominees vote at eviction (HOH breaks ties).
- **Eviction votes are secret ballots** (audit E12): the staged reveal reads anonymized ballots
  ("a vote to evict …"); per-voter attribution unseals **only** in the 0048 post-season
  retrospective. The player authors their **own goodbye messages** (a `goodbye-message` pending —
  tone is the player's choice; the engine never speaks for them, E34), and a player-juror asks
  their **own finale question** (E37).
- **Competition stats:** **Physical, Mental, Social** (no Luck stat). Outcomes are weighted by
  relevant stat vs. competition type + **temperature** plus an **emotional modifier** sourced
  from the houseguest's soul — **never** story convenience; the engine never protects the
  player. Emotional state is a *character/soul* attribute, not a fourth competition stat. The
  player may declare intent (compete / throw / play safe) before a comp and cannot change it
  retroactively.
- **Staged competitions (0006) are presentation over ONE roll.** An endurance comp resolves as a
  single calibrated `resolveCompetition` roll **up front** (byte-identical to the non-staged model),
  then plays out as a **presentation-only** staged elimination: the crown and the full drop order are
  fixed, and the per-round `comp-elimination` beats are **inert** (no rng, no fold, no soul inflection),
  so the staging can never perturb the winner or any downstream seeded roll. **Changing the staging is a
  calibration footgun** — `tests/unit/stagedTrajectoryNeutral.test.ts` is the byte-identity guard. Drops
  are **batched to ~4–8 rounds/comp** (`STAGED_TARGET_ROUNDS` in `liveSeason.ts`; owner ruling
  2026-06-20), and **only the first `comp-round` approach binds** — later rounds are non-binding flavor
  (the `binding` flag on the pending/`PendingDecisionView` drives the FE to render them as color, not a
  fresh decision). Lives in `src/engine/liveSeason.ts` (`advanceCompetition`) + `competitionOutcome.ts`.
- **Daily-event invariant:** every in-game day contains ≥1 meaningful event
  (comp, nomination/veto ceremony, vote/eviction, or significant house event).
- **Standard weekly cadence:** Day 1 HOH comp → Day 2 nominations → Day 3 veto comp →
  Day 4 veto ceremony → Day 5 eviction, with the next HOH beginning immediately. A genuine
  rest day is a rare producer judgment call, **not** the default.
- **In-game time of day & sleep (feature 0066 / ADR `docs/decisions/0006`; opt-in).** Time-of-day
  (morning → afternoon → evening → night → late-night) is first-class live-season state. Presence (0049)
  is **time-driven**: as the night gets late, NPCs turn in per character, the *awake set* shrinks, and play
  runs out of *people*, not a timer — the player owns their **own** bedtime (no forced curfew). **Sleep is
  consequential:** staying up late applies a **hidden, bounded** rest penalty in `resolveCompetition`
  (`src/domain/competitionOutcome.ts`), beside the soul emotional modifier — the player never sees a number,
  only the later behavior. Time-of-day is a Vault-free projection (a HUD + the player's own rest cue); NPC
  fatigue stays hidden. Governed by ADR 0006 (diegetic, character-driven bedtimes; the bound is the
  emptying house + escalating cost, never a curfew).
- **Jury & endgame:** the final **9 evictees** form the jury; how the player treats houseguests
  on the way out genuinely influences their later vote (jury management is a real mechanic). At
  Final 2 each finalist gives a statement and takes one question per juror. **Ties:** the HOH
  breaks an eviction-vote tie; the **last-evicted juror** breaks a tied jury vote.

## Workflow (BDD/TDD — follow strictly)

1. Translate the `bb-sim-spec.md` §12 invariants into **failing `.feature` files first**;
   implement to green; refactor.
2. **Strict priority order:** Vault isolation (incl. God Mode) → event visibility &
   propagation → behavioral fidelity → replayability/naming → competition eligibility →
   outcomes by stats+temperature → persistence non-degradation → daily-event.
3. Domain core under fast unit tests with the **seeded** `RandomnessSource`.
4. **Property-based tests** for randomness/temperature distributions and for behavioral-
   richness thresholds.

Suggested milestones M1–M8 are in `docs/CLAUDE_CODE_INSTRUCTIONS.md` §12 (start: pure domain
core, then ports + in-memory adapters with Vault/God-Mode isolation green).

## Testing rules (HARD)

- **No names in tests — roles only** (HOH, nominee, evictee, veto winner, NPC, player).
- **Sample saves are FORMAT ONLY.** Never ingest their *content* as canonical, seed, or test
  data. This includes the example persona and names in `docs/legacy/`.
- A player-facing **or admin** path isn't done until a test proves it returns **no** Vault data.
- Test that off-screen NPC life **exists** and that witnessed events are **not** secret.

## Hard "do-nots"

- Don't hold game state in a chat context window as the source of truth.
- Don't hard-code a **fixed cast** (ruling #1, 2026-06-10): name corpora are raw material, but no
  full-name+persona pairing may be hard-coded, and the legacy Bible's names stay banned. (NPC names
  are seeded samples from the vendored real-name corpora — never a fixed list, never a paired identity.)
- Don't reference names in tests; don't ingest sample-save content as data.
- Don't rely on prompt wording for the Vault Wall — enforce it in code.
- Don't let the narrative layer decide or alter outcomes.
- Don't expose Vault contents to **anyone** at runtime, including admin/God Mode — with the **single
  owner-ruled DEBUG exception** `producerVault` (the quarantined, out-of-band, admin-only, explicit-unseal
  live-Vault dump; see mandate #2). Never extend Vault exposure beyond it.
- Don't mislabel player-witnessed events as off-screen/secret.
- Don't let persisted detail degrade over time.

## Building & testing

Stack: **TypeScript / Node 22**, hexagonal, pure domain core. Test lanes: **Vitest**
(unit/property), **Cucumber.js** (the executable `.feature` specs), **fast-check** (used
selectively — most "property" suites are seeded fixed-loop distribution tests, which is
adequate for their claims; audit T18), and **dependency-cruiser** (the *structural* Vault-Wall
test — proves no outward module imports `VaultStore`/`VectorIndex`, type-only imports
included). Datastore: the default runtime is **in-memory + file**; a **SQLite (`better-sqlite3`) +
sqlite-vec** save store is **built and opt-in** (`ORWELL_STORE=sqlite`, engine-only, #330). **Postgres
+ pgvector** are the next tier behind the same ports (still deferred).

| Command | What it does |
|---|---|
| `npm install` | Install dependencies (dev toolchain + three pinned-exact runtime deps: `fastembed`, `better-sqlite3`, `sqlite-vec`). |
| `npm test` | Full gate: `typecheck` → `build` → unit/property/arch → BDD. |
| `npm run typecheck` | `tsc --noEmit`. |
| `npm run build` | Bundle the engine to `dist/main.js` + the embedding worker to `dist/embedWorker.js` (esbuild; `fastembed`, `better-sqlite3`, `sqlite-vec` stay external). |
| `npm start` | Run the built engine — the HTTP MCP server: the REST-ish tool API (`/:channel/{tools,call}`) **plus** an additive MCP/JSON-RPC 2.0 envelope (`POST /:channel/rpc` — `initialize`/`tools/list`/`tools/call`, notifications + batch; same auth/isolation guardrails). The SSE server-push stream is unimplemented and unneeded (no server-initiated messages). `ORWELL_ENGINE_PORT`, default 8765; `ORWELL_PORT` / `BBAI_*` are legacy fallbacks. |
| `npm run test:unit` | Vitest — unit, property, and the dependency-cruiser boundary test (the WHOLE suite, incl. the heavy sims). |
| `npm run test:unit:fast` | Vitest minus the two heavy simulation files (`tests/uat/**` + `juryReach`); what CI's `test` job runs via `test:ci`. |
| `npm run test:heavy` | Just the heavy simulation files (the full-game UAT — now three split files — + the juryReach and calibration-gradient gates); CI's parallel `heavy-sims` matrix runs them one-file-per-runner via `test:heavy:{uat-12seed,uat-5seed,uat-decisions,jury,gradient}`. |
| `npm run test:bdd` | Cucumber.js over the **implemented** `.feature` files. |
| `npm run test:arch` | dependency-cruiser CLI (forbidden-edge report). |
| `npm run test:cov` | Vitest with v8 coverage (excludes `src/ports/**`, `src/main.ts`, and the heavy sims — the v8-instrumented re-run of which added no gated-dir branch coverage). |
| `npm run test:ci` | The `test`-job composite: `typecheck` → `build` → `test:unit:fast` → `test:bdd` (the heavy sims run in the parallel `heavy-sims` job). |
| `npm run test:watch` | Vitest watch mode. |

- Single unit file: `npx vitest run tests/unit/visibility.test.ts`.
- Single BDD scenario: `NODE_OPTIONS='--import tsx' npx cucumber-js docs/features/0001-vault-wall-isolation.feature:LINE`.
- `cucumber.cjs` `paths` lists only the **implemented** features; add the next `.feature` there as each is built to green (priority order). It is the canonical list of what is wired into the BDD gate.
- **Test setup:** `tests/support/sandbox.ts` is the canonical test-environment factory — use it (not manual wiring) when adding new unit or integration tests. BDD step definitions use `features/support/world.ts`.
- **UAT lane:** the full-game UAT plays full games to completion; it is split across `tests/uat/fullGameUat.{12seed,5seed,decisions}.test.ts` (shared driver in `tests/uat/fullGameUatHarness.ts`) so its independent blocks fan out across separate CI heavy-sims runners. The 12-seed and 5-seed blocks bypass HTTP (direct callTool) to avoid CI stale-loop flakes; the decisions block drives real HTTP. All run as part of `vitest run`.
- **Runtime env:** `ORWELL_DATA_DIR` is the per-user save dir (default `.orwell-data` — the factory-reset script must scrub it). `ORWELL_STORE=sqlite` selects the built SQLite + sqlite-vec save store (engine-only, #330); unset ⇒ the default in-memory + file path. **Pure turn-driven is the DEFAULT** (`ORWELL_WATCHER_TICK_MS=0` — ruling 2026-06-10: the game clock is the player's play-clock; the house lives between the player's own turns via one bounded off-screen tick per turn and does **not** exist while the player is away — NPCs can't leave the house, the player can, so background advances during an absence are a structural disadvantage). `ORWELL_WATCHER_TICK_MS` / `ORWELL_WATCHER_IDLE_MS` / `ORWELL_WATCHER_MAX_TICKS` opt in to the wall-clock watcher — never the default. HTTP edge: `ORWELL_ENGINE_HOST` (default loopback), `ORWELL_ENGINE_TOKEN` (shared secret on every tool route), `ORWELL_ENGINE_ADMIN_TOKEN` (a **separate** secret for `/admin/*` — player ⊉ admin, audit E27), `ORWELL_ENGINE_MULTIUSER` (reject a missing `x-orwell-user` instead of routing to "default"). Semantic recall: `ORWELL_EMBEDDINGS=fastembed` (the deploy default; unset ⇒ deterministic fake), `ORWELL_EMBED_CACHE` (model cache dir), `ORWELL_TEST_FASTEMBED=1` (opt-in real-model integration test — tests never depend on real embeddings otherwise).
- **Front-end tests:** `cd frontend && python3 -m pytest tests/` (its own pytest gate, quarantined — never touches `cucumber.cjs` / `npm test`); `frontend/scripts/boot_smoke.py` boots the real app and proves the game-build gating server-side; `frontend/scripts/browser_smoke.py` is the headless-browser keep-set gate; `frontend/scripts/responsive_matrix.py` is the viewport×surface matrix gate (Stream S, ruling #16 — overflow/overlap/tap-target checks with an XFAIL registry). The reduced game surface is controlled by `ORWELL_GAME_BUILD` (default **on**; `=0` restores the full inherited workspace).
- **Running locally (two processes):** the engine and front-end are **separate services**. Engine — `npm run build && npm start` (HTTP MCP on `ORWELL_ENGINE_PORT`, default 8765). Front-end — `cd frontend && python3 -m uvicorn app:app --host 127.0.0.1 --port 7000`, pointed at the engine via `ORWELL_ENGINE_MCP_URL` (default `http://127.0.0.1:8765`); it consumes **only** Vault-free projections (handshake in `frontend/INTEGRATION.md`). `deploy/smoke.sh` boots both and drives a full turn end-to-end (the same path CI's deploy-smoke job runs).
- **Live (real-LLM) manual testing:** every automated gate **stubs the LLM** (`DeterministicNarrator`/`Echo…`),
  so the real player journey (casting interview → in-character narration → the agent loop) is exercised
  **only** by wiring a real model into the FE: `POST /api/model-endpoints` with the provider `base_url` +
  `api_key` (admin-gated, but `require_admin` short-circuits when `AUTH_ENABLED=false`), then set
  `default_model` + `default_endpoint_id` in `frontend/data/settings.json` (read per-request — no restart).
  `GET /api/default-chat` confirms what resolves. This is the path to reproduce LLM-only bugs (tool
  under-calls, narration desyncs) the gates can't see.
- **CI** (`.github/workflows/ci.yml`, #351): **per-job path-filtering** + **sharded heavy lanes** under a single required check. A `changes` job emits booleans; each job gates on the relevant paths (a docs-only/FE-only PR skips the engine + heavy lanes) and a unified **`ci-gate`** (always-runs, `success`/`skipped` ⇒ pass) is the one required check — deadlock-free on an all-skip. Jobs: the engine gate (`npm run test:ci`: typecheck → build → unit/property/arch minus the heavy sims → BDD), the **heavy-sims** lane **sharded** for wall-clock (UAT 12→3 `uat-12seed-{a,b,c}`, `uat-5seed`, `uat-decisions`; **jury** 20→5 `jury-shard` + `jury-aggregate`; **gradient** 6→2 `gradient-shard` + `gradient-aggregate` — each shard plays a disjoint seed slice, the aggregate recombines and asserts the full band; every heavy lane now < ~3 min), the coverage gate (`npm run test:cov`, per-directory **branch thresholds** in `vitest.config.ts`: engine 90 / composition 88 / adapters-engine 82 — ratchet up only; heavy sims **and** the calibration data instrument `tests/calibration/**` excluded), the deploy smoke (`bash -n` every script + `deploy/smoke.sh`, which boots the real engine **and** front-end and drives a full turn), and the front-end jobs — **`fe-unit`** (py_compile → the ~3750 non-browser pytest tests **parallel** under `pytest-xdist -n 4` → JS syntax check; ~1.5 min vs the old ~12.5-min serial run), **`fe-browser-tests`** (the ~100 `sync_playwright` tests — auto-marked `browser` in `frontend/tests/conftest.py` — run **serial with `--reruns 1`** so the known onboarding-scrim flake #925/#1148/#930 self-recovers), plus **`fe-browser`** (boot + browser smoke) and **`fe-responsive`** (viewport matrix). Every job carries a `timeout-minutes` cap and a per-test `pytest-timeout` (`frontend/pyproject.toml`) so a wedged test or a self-hosted-runner blip fails fast instead of hanging — the split's shorter jobs also survive a fleet drop that would guillotine a 12-min one.
- **Deploy** (`deploy/`): the repo is **private** (ruling #17) — `orwell.sh` (run on the Proxmox host) creates the LXC, persists the one-time `GIT_TOKEN` PAT into `data/.env` with a git credential helper, and runs `orwell-install.sh` (apt + Node 22 + Python, pinned `requirements.lock.txt`, systemd units from `deploy/systemd/`, hardened per E85; UI ports <1024 get a `CAP_NET_BIND_SERVICE` drop-in; optional `CT_ROOT_PASSWORD` for console login). Maintenance scripts are host-aware (bridge into the LXC via `pct`), run from the **local checkout** (never a GitHub fetch of branch tips), and fall back to a legacy container named `bbai` (ruling #6): `orwell-update.sh` (also `--set-token` for PAT rotation) · `orwell-doctor.sh` (diagnose/bounce) · `orwell-backup.sh` / `orwell-restore.sh` · **three reset tiers** — `orwell-game-reset.sh` (new season: clears every engine sandbox, **preserves** accounts/sessions/LLM config/`data/.env`, ruling #2) · `orwell-oobe-reset.sh` (back to OOBE, **keeps the API key(s) + provider endpoint; RESETS the selected models to the OOB defaults** — narrator `deepseek/deepseek-v4-pro`, portrait `gemini-2.5-flash-image` — via `frontend/scripts/oobe_reset.py`, issue #860; wipes the rest of the FE store) · `orwell-factory-reset.sh` (the host "factory reset" — now **delegates to `orwell-oobe-reset.sh`** so "factory reset" keeps your LLM credentials everywhere, matching the admin **Factory Reset (OOBE)** button + the `orwell-ops-factory-reset` unit; preserves API key(s)/endpoint + `data/.env`, **resets selected models to defaults**, wipes everything else) · `orwell-login-panel.sh` (the interactive-shell health panel, ruling #21 — never blocks a login) · the **`orwell` control panel** (`orwell-menu.sh` + the shared whiptail helpers `orwell-tui.sh`, installed as `/usr/local/bin/orwell`) — a TUI menu wrapping update/doctor/backup/restore/resets/ready; the maintenance scripts also show inline whiptail dialogs (token password box, type-`RESET` confirm, doctor mode picker) on a TTY and stay fully non-interactive (flags/env) for automation/CI/the `pct` bridge — `whiptail` is apt-installed, absent ⇒ plain-prompt fallback · `orwell-ready.sh` · `deploy/smoke.sh` + `smoke_turn.py` (post-deploy checks). Front-end (`frontend/`, Python/FastAPI) is its own quarantined app — see `frontend/INTEGRATION.md`.

**Source layout:** `src/domain` (pure core, no I/O) · `src/ports` (interfaces — `VaultStore`,
`VectorIndex`, `EmbeddingProvider`, `SoulProvider` are **engine-only**; outward ports include
`EngineCommands`, `GameSession`, `NarrativePort`/`StreamingNarrativePort`, `ImageGenerationPort`
(0051 — **outward by construction**: the engine emits only Vault-free portrait prompts, the FE owns
the concrete provider), `SaveStore`/`UserSaveStore`) · `src/services` (`VisibleStateService` / `SummaryService` — outward-safe) ·
`src/surfaces` (`player/`, `admin/`, `tools/` — no Vault handle by construction) · `src/adapters`
(`inmemory/`, `engine/` (the live `GameSessionAdapter` / `EngineCommandsAdapter`, `FileSaveStore`,
`SoulStore`), `mcp/` (`McpServer` / `HttpMcpServer`), `narrative/` (`LlmNarrativePort`,
`DeterministicNarrator`, `Echo…`), `embedding/` (`FastembedEmbedding` + its worker-thread bridge,
`DeterministicEmbedding` — the test adapter and runtime fallback), `image/`
(`NoopImageGenerationPort` — the null adapter used when no image-capable provider is wired; 0051),
`random/`, `time/`) ·
`src/engine` (the season loop `season.ts` + the live loop `liveSeason.ts`, plus `conversation.ts`,
`relationships.ts`, `consequence.ts` (the original 0023 hidden-impact fold module — the **live**
folds run in `GameSessionAdapter`/`EngineCommandsAdapter`), `gossip.ts`, `offscreen.ts`,
`confessionals.ts`, `deals.ts`, `blocs.ts`, `presence.ts`, `emotionalArc.ts`,
`competitionLibrary.ts`, `houseEvents.ts`, `castingIntake.ts`, `momentPrompts.ts`,
`portraitPrompts.ts` (the Vault-free, public-facets-only portrait-prompt builder) +
`imageConstants.ts` (0051 per-turn/-week generation budget caps), `data/` (the
vendored real-name corpora), and tunable constants) · `src/composition`
(`engineRoot` wires the Vault; `outwardRoot`/`appRoot` never do; `orchestrator.ts` is the
per-sandbox **commit/integrity spine** with a fail-closed checkpoint — game advances also flow
through the session's `advanceGame`/`submitDecision`, with the orchestrator as the commit hook —
driven by `gameWatcher.ts` over a `registry` of per-user sandboxes; `runtime.ts` composes +
starts the live watcher from `src/main.ts`). **There is ONE sanctioned season-restart door**
(audit D1/R1): `registry.resetUser` → `Orchestrator.forgetUser` + save-dir rotation — the
player channel's confirmed `createCharacter` restart delegates through that same hinge, a
refused commit throws typed (409, never 200-then-rollback), and `POST /api/orwell/new-game` is
admin-gated. Never add a second restart path. BDD steps + support in `features/`; unit/property/
architecture/integration tests in `tests/`. The
`.feature` files in `docs/features/` remain the source of truth. The **player-facing tier** is the
vendored **Orwell** front-end in `frontend/` (Python/FastAPI) — its own app, quarantined from the
TS tooling (see `frontend/INTEGRATION.md`).

## Current status

**Built BDD/TDD-first and feature-complete through the originally-drafted spec set (0001–0074).** The eight
priority invariants, the MCP seam, the full weekly loop, per-user sandboxes, durable persistence, the
live off-screen society, the endgame + interactive finale, the character-evolution linchpin (0041),
deep character profiles (0058), seasons-as-levels, multi-device sync (0064), the LLM↔engine sync spine
(0065), in-game time + the sleep economy (0066 / ADR 0006), public-internet exposure (0067/0068 / ADR
0007), the token economy + usage envelope (0069), off-screen texture enrichment (0070), defensive
hardening (0071), the multi-platform gateway (0072), the structural anti-sycophancy game-build wall as
a CI gate (0073), and local & tunable HTTPS (0074 / ADR 0014) are all in. **Past 0074 the spec set runs to 0110**:
**0075–0093, 0099–0100, 0102, 0104–0107, 0109, 0110** are built (trust-gated confidences, presence/eyeshot & motivated
movement, the runtime overseer 0079–0081, character voice/campaigns/drives, secrets-as-power,
jury grudge book, season notoriety, named alliances, deal duration, vote deduction, the daily recap
0102/#884), while **0094–0098, 0101, 0103**
remain **spec-only/frozen** (the Producer's-Vault audit + PO-review batch — opt-in/default-off social
texture, some parked, some awaiting a build slot) and **0108** is spec-only (the real-model
golden-path gate).
**0022** (the rich game UI / MVP-2) was **removed** in the 2026-06-28 PO review — by ADR 0003 the chat *is*
the UI, and its goals were delivered chat-forward via 0020/0051/0054, so the standalone dashboard spec was cut.

**Trust the code over this prose — it drifts.** The authoritative sources, in order:
- `docs/features/README.md` — the per-feature status index, reconciled against the source (built /
  spec-only / deferred, with each feature's verification gate).
- `cucumber.cjs` `paths` — the live list of BDD-gated features.
- `docs/audits/2026-06-10-full-product-audit.md` (the close-out ledger) — the authoritative open-items
  list going forward, and `docs/audits/2026-06-21-open-items-verification.md` — the source-verified,
  tier-organized snapshot of every open item as of **2026-06-21** (which tracker rows were stale then;
  no launch-blockers remain). It predates the entire 0075–0112 batch — for anything after 2026-06-21,
  `docs/features/README.md` is the source of truth, not this snapshot.
- `git log --oneline` for what last merged green; `npm test` for the authoritative pass/fail.

**A few load-bearing invariants worth knowing up front** (enforced in code; easy to violate by accident):
- `runCompetition` is the **single outcome authority** — `resolveCompetition` is not on the player
  channel — and `recordInteraction` requires the player actually witnessed the scene.
- The live engine-side narrator is `EchoNarrativePort`; **narration happens in the front-end** via
  `getMomentPrompt` (the `setNarrator` seam exists if engine-side narration is ever wired).
- Souls evolve live (`src/engine/emotionalArc.ts`) and bend the competition modifier; `CHARACTER` stays
  byte-stable; no number ever crosses to the player.

**Open forward work** (new work starts as a new spec/queue item; the close-out ledger is authoritative).
*A source-verified, tier-organized snapshot of every open item — and which tracker rows are stale — is
`docs/audits/2026-06-21-open-items-verification.md` (no launch-blockers remain):*
- **Calibration tuning — re-measured 2026-06-21, primary goal MET; no change pending.** The
  `JURY_WEIGHTS.gameRespect` 0.9→0.7 drop (PR #364) + engine evolution flipped the old inversion: on
  current main a 30-seed instrument run shows **active wins 20% vs passive 7%** (F2-blowouts 50% vs 63%) —
  playing the game now converts. **Do NOT lower `gameRespect` further** (0.65 would over-correct a solved
  problem). Residual (optional, low-pri): passive still *reaches* F2 about as often (a reach-side lever,
  `decisionConstants.juryManagementWeight` / audit #4, if desired) — reads as emergent realism, not a
  defect. The `tests/property/juryReach.property.test.ts` `EARNED_WINS` guard stays the permanent gate.
  Re-measurement + the stale-doc flags: `docs/audits/2026-06-21-session-observations.md`.
- **ADR 0006 / 0066 Phase-2 — on the PO review list.** Deferred time/sleep extensions: NPC *next-day*
  social fatigue, a compounding multi-night fatigue meter, and per-conversation clock advance (vs. the
  current per-beat) — owner decisions in `docs/features/0066-in-game-time-and-sleep.md` §9.
- **0022** (MVP-2, the rich game UI) was **removed** in the 2026-06-28 PO review (superseded by
  0020/0051/0054 under ADR 0003) — there is no longer a deferred/parked MVP feature. *(0059 hidden seeded
  relationships is **built** — `src/engine/seededRelationships.ts` + `seededRelationships.test.ts`,
  orientation-aware via 0063; this line previously mis-listed it as spec-only. Reconciled 2026-06-21.)*
- **0010** container smoke on a real Proxmox host (also the A4 single-PAT deploy verification — do it
  during the private-repo flip).
- **Postgres + pgvector** relational tier — MVP-002 post-launch scale-out (SQLite + sqlite-vec shipped
  opt-in, #330); only matters past a single-host deploy.

## Open decisions (remaining)

**Resolved:** tech stack, datastore, and vector adoption (above); soul storage = markdown +
vector behind `SoulProvider`; non-degradation strategy = superset + monotonic-count + lossless
round-trip (`docs/features/0007-persistence-non-degradation.md`); drop Luck → emotional
modifier; Character/Soul split; organic relationship model; veto "Houseguest's Choice"
(`docs/decisions/`). **Mostly resolved — none block current work:**

1. ✅ **Temperature & emotional-modifier constants** — **resolved**: the *shape* is fixed in
   `docs/features/0006-…` / `docs/decisions/0001`, and the numbers are firmed into the single tunable
   module `src/domain/temperatureConstants.ts` (**feature 0028**). Only fine-tuning remains.
2. ✅ **Relationship-model math** — **resolved** by **feature 0026** (`src/engine/relationshipConstants.ts`):
   signal set, update rule, recency/decay, betrayal-shock, thresholds (promotes `docs/decisions/0002`).
3. ✅ **Jury choreography** — **resolved** by **feature 0037** (the live interactive finale: statements →
   per-juror questions → ordered vote reveal). Reserve twists stay Vault-held (0025).
4. ✅ **Embedding provider** — **decided AND built** (ADR `docs/decisions/0004`; E86a,
   2026-06-11): **fastembed, local ONNX** (the JS port + model both version-pinned) is the
   runtime `EmbeddingProvider` — warmed up at boot (`ORWELL_EMBEDDINGS=fastembed`, the deploy
   default), served synchronously through a worker-thread bridge, with the deterministic fake
   as both the test adapter and the whole-process fallback when the model is unavailable.

5. 🆕 **In-game time, sleep & the nightly presence economy** — ADR `docs/decisions/0006`, built **opt-in** as
   feature **0066** (time-of-day on the live season; presence 0049 made time-driven — the awake set shrinks as
   NPCs turn in per character, the player owns their **own** bedtime, no curfew; a hidden bounded **rest** term
   beside the emotional modifier in `src/domain/competitionOutcome.ts`, never shown to the player). Only *tuning*
   is open — the bound's exact feel, and whether sleep cost reaches past competitions — per ADR 0006's
   "Open / to confirm".

6. ✅ **Public exposure, cross-device consistency, location, token economy, the live mirror & local HTTPS** — ADRs
   **0007–0014**, all **accepted and built** (features 0067/0068 public exposure, 0069 token
   economy/usage envelope, 0074 local & tunable HTTPS (ADR 0014), and the 0008/0011/0012 multi-window seams all shipped). Their *residual* open
   items are **tuning, owed
   verification runs, and post-launch refactor** — **not** unbuilt architecture: ADR 0010 token-economy
   follow-ons (per-class `max_tokens` runtime-edit; model-aware reasoning sizing; ledger
   `appliedMaxTokens`/`finishReason`; `Continue ▸` in chat mode), the ADR 0008/0012 live-LLM two-window
   re-run + mid-gen-join test pin, and the architecture latents filed in `docs/REFACTOR-ROADMAP.md`
   (R1–R7, post-launch — the highest-value being **A-S3**, a stale-409 that can drop a scene's only
   consequence fold). The full source-verified status is
   `docs/audits/2026-06-21-open-items-verification.md`.

# Roadmap — Post v1.0.0 (Branched by Day-7 Outcome)

Goal-backward roadmap for episteme beyond the v1.0.0 soak close. Three
execution branches anchored to Day-7 gate-grading outcomes + five
milestone themes + explicit non-goals per milestone + dependency graph
+ lessons-from-adjacent-ecosystems appendix (Hermes v2026.4.23 + Langfuse
v3.170.0) + Event-53 audit log of items considered and removed on
governance-mandate grounds.

Drafted Event 51 (2026-04-24), extended with Langfuse analysis Event 52,
audited + trimmed Event 53. All 6 pre-soak infrastructure CPs landed
(Events 47-50); soak clock runs toward ~2026-04-30 close.

**Event 55-56 (2026-04-25) — v1.1+ architectural vision drafted &
APPROVED (first pass).** See
[`docs/DESIGN_V1_1_REASONING_ENGINE.md`](./DESIGN_V1_1_REASONING_ENGINE.md)
for the full synthesis of three structural epiphanies that transition
episteme from *reactive logging/blocking* to a *proactive reasoning
engine*. Locked-in framing: **3 Cognitive Arms** (Arm A · Temporal
Integrity, Arm B · Causal Synthesis, Arm C · Self-Consistency
Convergence) operating on top of v1.0's three Pillars — Pillars are the
unchanging structural foundation; Arms are the fluid active engines
refactoring the kernel's own knowledge over time. Status flipped Event
56: `drafted (vision)` → `approved (reframed, first pass)`. Six operator
decisions in the first-pass approval: (1) `3 Cognitive Arms` naming
(NOT Pillar 4-6); (2) staggered verification windows 30d/60d/90d; (3)
Cognitive Arm C ships CP-MODEL-01 cross-protocol consistency check in
v1.1 (vision without execution = Doxa); (4) **D11 Operator Fatigue
Guardrails** added — sub-second approval times flag as
`attention_bottleneck` drift signal; (5) Claude Code first per BYOS, no
multi-adapter parity at v1.1 GA gate; (6) Zero-LLM Entity Extraction
precision/recall named the primary technical risk for Arm B. v1.1 CP
work begins only after v1.0 GA cut + soak gates resolve favorably. The
roadmap below is unchanged operational planning; the design document
carries the architectural reasoning.

---

## 0. Governing intent — the anchor everything traces back to

Restated from the operator's own words (Event 6 third-pass reframe;
also in `kernel/CONSTITUTION.md` and
`docs/COGNITIVE_SYSTEM_PLAYBOOK.md` § 1):

> There is so much information in the world. When I search the
> internet or look at docs, how do I distinguish what is actually
> correct or what specifically fits MY context? Source A says "do
> it this way", Source B says "do it that way". There is an
> underlying know-how or protocol hidden in these multiple cases.
> I want a system that systematically breaks this chaos down,
> understands WHY the sources conflict, creates a thinking
> framework that can continuously update itself, and then uses
> the insights generated from this framework to actively GUIDE me
> in the right direction.

Four jobs the kernel must do to satisfy this:
1. **Per-action causal decomposition** — Pillar 1 Cognitive Blueprints
2. **Per-case protocol synthesis** — Pillar 3 synthesis arm on
   Axiomatic Judgment + Fence Reconstruction + Blueprint D
3. **Proactive guidance at future decisions** — Pillar 3 advisory
   stream at PreToolUse
4. **Continuous self-maintenance** — Blueprint D architectural cascade
   + deferred-discovery logging + retrospective sync-plan verification

Every milestone below must explicitly map to ≥1 of these four jobs.
Items that don't map are scope creep.

---

## 1. Current state (pre-soak-close) — what's in the box

| Capability | Status |
|---|---|
| Pillar 1 · Four named blueprints (A·B·C·D) + generic fallback | ✓ shipped |
| Pillar 2 · Hash-chained episodic + pending-contracts + framework streams | ✓ shipped |
| Pillar 3 · Framework synthesis arm on Fence Reconstruction | ✓ shipped |
| Pillar 3 · Advisory guidance at PreToolUse | ✓ shipped |
| Phase 12 · Profile-audit loop (4 axes deeply-worked, 11 stubbed) | ✓ shipped; drift detection verified Event 48 |
| Exit-code extraction (CP-TEL-01) | ✓ Event 49 |
| Framework dedup-on-log (CP-DEDUP-01) | ✓ Event 49 |
| Correlation-id mismatch (CP-FENCE-02) | ✓ Event 50 |
| Discriminator calibration (CP-DISC-01) | ✓ Event 47 |
| Gate-grading tools (`tools/grade_gates.py` etc.) | ✓ Events 47-50 |
| v1.0.0 governance docs (rubric, triage, prepared patches) | ✓ Events 46-50 |

Current grader baseline (subject to Day-7 fresh-evidence collection):
**3 PASS · 4 MANUAL · 1 FAIL · weighted 3.0/4.0**. Gate 26 FAIL will
likely flip on the first soak-window fence_reconstruction op now that
CP-FENCE-02 has landed.

---

## 2. Day-7 branched paths

Three branches per `docs/POST_SOAK_TRIAGE.md` §4 decision rule.

### 2.A — GA path (≥ 4/8 clear-pass, Gate 28 ≥ PARTIAL)

v1.0.0 GA released. release-please PR #2 merges with operator's
post-soak version-bump decision. Next milestone opens immediately as
**v1.0.1 · Evidence Pipeline Hardening** (§3.1 below). Remaining
MANUAL/FAIL gates named as v1.0.1 scope in release notes per the
honest-disclosure requirement (§4.4 POST_SOAK_TRIAGE).

Estimated calendar: 1 week from GA to v1.0.1-rc1 soak open.

### 2.B — v1.0.1-rc path (2-3 clear-pass)

No GA. v1.0.1-rc1 cycle opens with the top-priority CPs from §3.1
folded in before re-soak. This is the most realistic outcome given
current baseline and remaining MANUAL gates.

Estimated calendar: 2-3 weeks of CP execution + fresh 7-day soak.

### 2.C — scope-retreat path (≤ 1 clear-pass)

Cognitive-adoption thesis not holding up under measurement. Two
options:
- **2.C.i** — demote cognitive-adoption from v1.0 headline; ship v1.0
  on engineering-gates only; cognitive-adoption becomes v1.1 roadmap
  item. Release notes are honest about the retreat.
- **2.C.ii** — defer v1.0 entirely; fold cognitive-adoption and
  engineering completeness into v1.1.

Should not be reached given current baseline (3 PASS already), but
named explicitly so the decision-making is always branch-aware.

---

## 3. Milestone themes — organized by dependency order

Five themes cluster the remaining scope. Each theme has a dedicated
milestone section below.

```
  ┌─────────────────────────────────────────┐
  │ Theme 1: Evidence Pipeline Hardening    │
  │         (v1.0.1 — highest priority)     │
  └───────────────┬─────────────────────────┘
                  │
     ┌────────────┴────────────┐
     ▼                         ▼
  ┌─────────────────┐    ┌──────────────────────┐
  │ Theme 2:        │    │ Theme 3:             │
  │ Schema Evolution│    │ Behavior Knobs       │
  │ (v1.0.1-v1.1)   │    │ (v1.0.1-v1.1)        │
  └────────┬────────┘    └──────────┬───────────┘
           └────────────┬───────────┘
                        ▼
          ┌─────────────────────────────┐
          │ Theme 4: Framework          │
          │         Consolidation (v1.1)│
          └──────────────┬──────────────┘
                         ▼
          ┌─────────────────────────────┐
          │ Theme 5: Cognitive-Adoption │
          │ Gates Raising (v1.2)        │
          └─────────────────────────────┘

  Cross-cutting (any milestone):
  - TUI + observability surface (§3.6)
  - Multi-project framework consolidation (§3.7, v2.0 candidate)
```

### 3.1 Theme 1 — Evidence Pipeline Hardening (v1.0.1)

**Maps to Jobs 1 + 2 + 4.** Ensures the kernel's own evidence-
collection machinery is honest before we raise gates or add features.

CPs in execution-priority order:

| CP | Scope | Effort | Counters FAILURE_MODE |
|---|---|---:|---|
| CP-FENCE-02 | correlation-id mismatch | ✓ applied Event 50 | narrative-fallacy (broken-pairing-masquerading-as-no-evidence) |
| CP-TEL-01 | exit_code extraction | ✓ applied Event 49 | WYSIATI (null-extraction feels complete) |
| CP-DEDUP-01 | framework dedup-on-log | ✓ applied Event 49 | narrative-fallacy (1,294 records feels like 1,294 findings) |
| CP-DEDUP-02 | retroactive dedup of existing 1,294 records | 1 day | same |
| CP-CROSSREF-01 | unique-file-count cross-ref proxy (deferred #2) | 0.5 day | overconfidence |
| CP-CASCADE-01 | exempt kernel state files + read-only ops from cascade (deferred #1 + #26) | 1 day | fence-check (detector firing on own state) |
| CP-CHKPT-01 | auto-checkpoint re-fires fix (deferred #27) | 1 day | planning-fallacy (premature-chkpt commits) |
| CP-SMOKE-01 | installable-plugin smoke test in RC engineering gate (deferred #20) | 1 day | WYSIATI (gate didn't see what was actually broken) |

**Non-goals for v1.0.1**:
- Do NOT add new cognitive-adoption gates (Theme 5 territory).
- Do NOT add new blueprints (Theme 4 territory; current A/B/C/D is
  load-bearing and proven).
- Do NOT introduce new CLI UX features (cross-cutting §3.6
  territory — v1.1 scope).

**Acceptance criteria for v1.0.1**:
- All CPs above applied + tested.
- Grader weighted-pass reaches ≥ 5.5/4.0 (Gate 22/26 PASS; Gate 25 +
  21 + 27 remain PASS; Gate 28 PASS via pre-audit upgrade; Gates 23 +
  24 PARTIAL at minimum).
- `~/.episteme/framework/protocols.jsonl` contains ≥ 5 real protocol
  entries from soak-window fence_reconstruction ops.
- `framework/deferred_discoveries.jsonl` growth rate drops to < 10
  records/day (from current ~67/day) via CP-DEDUP-01 + -02.

### 3.2 Theme 2 — Schema Evolution (v1.0.1 → v1.1)

**Maps to Job 1 (blueprint field fidelity) + Job 4 (self-maintenance
schema drift detection).** Closes the 4+ schema gaps logged in
deferred discovery #37 + makes schemas reflect what the kernel
actually needs.

| CP | Scope | Effort | Milestone |
|---|---|---:|---|
| CP-SCHEMA-01a | `flaw_classification` enum gains `doc-positioning-drift` + `scope-creep` | 0.25 day | v1.0.1 |
| CP-SCHEMA-01b | `posture_selected` enum gains `audit-pass` (non-patch/non-refactor review state) | 0.25 day | v1.0.1 |
| CP-SCHEMA-02 | add `reasoning_failure_mode` surface field for FAILURE_MODES.md citations (Path 4B — referenced in Gate 27 resolution, deferred #37) | 2 days | v1.1 |
| CP-SCHEMA-03 | migration tooling: episteme kernel evolve — auto-upgrade in-flight surfaces when schema changes | 3 days | v1.1 |

**Non-goals**:
- Do NOT extend blueprint field counts beyond what's proven necessary.
  Adding fields is easy; retiring them breaks past records. Every
  addition requires a counter-factual ("what failure mode does this
  field counter that no existing field captures?").

**Acceptance criteria**:
- Post-schema-02, Gate 27 migrates from kernel-prose-only grading to
  dual-axis (prose + episodic-field) grading.
- No silent schema breaks — all evolution paths have test coverage.

### 3.3 Theme 3 — Behavior Knobs (v1.0.1 → v1.1)

**Maps to Job 3 (active guidance).** Operationalizes the orphan knobs
+ adds the Ashby escalate-by-default mechanism.

| CP | Scope | Effort | Milestone |
|---|---|---:|---|
| CP-KNOBS-01 | `default_autonomy_class` wired to reasoning-surface-guard admit/defer/reject decision (deferred #5) | 2 days | v1.0.1 |
| CP-KNOBS-02 | `fence_check_strictness` wired to Blueprint B strictness threshold (deferred #5) | 2 days | v1.0.1 |
| CP-ASHBY-01 | escalate-by-default for out-of-coverage action shapes (FAILURE_MODE 9 counter; deferred #6) | 3 days | v1.1 |
| CP-JAYNES-01 | evidence-weighted assumption update — posterior plausibility on reasoning_surface.assumptions[] entries; epistemic decay schedule (deferred #7) | 5 days | v1.1 |

**Non-goals**:
- Do NOT make knobs runtime-mutable from agent-side code. Operator-
  only config surface (`core/memory/global/operator_profile.md` +
  `episteme sync`). The kernel controls the knobs; the agent
  doesn't.
- Do NOT add global knobs that don't have a failure-mode counter.

**Acceptance criteria**:
- Post-KNOBS-01+02, session-level behavior visibly different between
  `default_autonomy_class: reversible-auto` vs
  `default_autonomy_class: irreversible-only-gate`.
- Post-ASHBY-01, ≥1 real out-of-coverage action during v1.1 soak is
  caught + escalated (spot-check verdict records this).

### 3.4 Theme 4 — Framework Consolidation (v1.1)

**Maps to Jobs 2 + 3 + 4.** Turns the protocols.jsonl stream from a
flat log into a queryable graph that the advisory system actually
uses with high recall.

| CP | Scope | Effort | Milestone |
|---|---|---:|---|
| CP-GRAPH-01 | Stop-hook async maintenance worker (consolidates protocols into context-signature graph) | 5 days | v1.1 |
| CP-GRAPH-02 | zero-LLM entity extractor on every reasoning-surface write (regex + heuristic cascade, pattern from gbrain) | 3 days | v1.1 |
| CP-GRAPH-03 | `episteme guide --context=<signature>` Recall@5 benchmarking (synthetic corpus target per NEXT_STEPS entry) | 2 days | v1.1 |
| CP-GUIDE-01 | cross-session guidance replay — last-session context-signature + advisory continuation at SessionStart | 2 days | v1.1 |
| CP-RETRO-01 | retrospective sync-plan completeness verification (cross-surface orphan-reference detection; spec-deferred since CP10 — deferred #4) | 4 days | v1.1 |

**Non-goals**:
- Do NOT invoke LLMs on the write path. Entity extraction stays
  regex+heuristic per gbrain discipline; Recall@5 quality is the
  metric, not semantic depth.
- Do NOT produce advisory blocks. Guidance is always advisory per
  Pillar 3 design — collapsing to enforcement creates a feedback
  loop where the kernel enforces its own synthesis against the
  operator.

**Acceptance criteria**:
- Framework graph emits ≥ 10 non-trivial protocols after 30-day soak.
- `episteme guide` query returns context-matched protocols at
  Recall@5 ≥ 0.7 on synthetic test corpus.
- ≥ 1 operator spot-check verdict confirms advisory guidance was
  helpful (not just technically correct but operator-valuable).

### 3.5 Theme 5 — Cognitive-Adoption Gates Raising (v1.2)

**Maps to all four Jobs via measurement.** Strengthens the Day-7
rubric so v1.2+ releases have higher bar than v1.0.

| CP | Scope | Effort | Milestone |
|---|---|---:|---|
| CP-GATE-01 | raise Gate 21 form-filling rate threshold from > 40% band-downgrade to > 25% (after 50+ record corpus calibration per CP-DISC-02) | 1 day | v1.2 |
| CP-GATE-02 | add Gate 29 — `synthesized_protocol` refs trace to ≥2 distinct reasoning-surface fields per emission | 2 days | v1.2 |
| CP-GATE-03 | add Gate 30 — cascade-theater audit: sampled Blueprint-D firings show ≥ 60% "real sync" verdict (Layer 8 discipline) | 2 days | v1.2 |
| CP-GATE-04 | add Gate 31 — guidance-acted-on rate: advisory emissions with operator spot-check "used" verdict / total emissions ≥ 10% | 2 days | v1.2 |
| CP-DISC-02 | discriminator threshold re-calibration against 50+ record post-v1.0 corpus | 1 day | v1.1 prereq |

**Non-goals**:
- Do NOT raise gates before v1.0.1 evidence pipeline hardening
  completes. Raising gates on broken infrastructure produces noise.
- Do NOT add gates that only one kind of work triggers. Every new
  gate must match ≥ 3 distinct op classes to avoid gate-gaming.

**Acceptance criteria**:
- v1.2 baseline ≥ 6/11 clear-pass on raised bar.
- v1.2 honest-disclosure release notes show which gates tightened
  and why.

### 3.6 Cross-cutting — TUI + observability (v1.1 candidate)

**Maps to Job 3 (guidance visibility).** Inspired by Hermes
v2026.4.23's Ink-based TUI (see §5). episteme benefits from
visualizing the reasoning-surface + framework protocol emissions +
Phase 12 drift + gate-grading state in real-time.

| CP | Scope | Effort | Milestone |
|---|---|---:|---|
| CP-TUI-01 | `episteme tui` — Textual-based (Python-native; avoid Node/Ink dep) read-only dashboard surfacing EXISTING `~/.episteme/*.jsonl` streams: current reasoning-surface status, episodic-record stream, recent framework protocols, Gate 21-28 live grading. No new data model; the TUI reads what grade_gates.py / discriminator_calibration.py already produce. | 5-7 days | v1.1 |
| CP-TUI-02 | subagent-spawn observability overlay (map Task-tool invocations to Blueprint-D surface + outcome per spawn). Lower priority — UI polish atop existing cascade detector. | 3 days | v1.2 (optional) |

**Non-goals**:
- Do NOT build a TUI that tries to REPLACE the Claude Code / Hermes
  agent surface. episteme is a governance layer; the TUI is
  observability into our layer, not an agent chat UI.
- Do NOT introduce a Node/Ink dependency for core CLI. TUI is
  optional, Python-native (Textual library), installable as extra.
- Do NOT build a parallel web dashboard that mirrors TUI
  functionality (CP-WEB-01 was considered Event 51 and REMOVED
  Event 53 — see §7 Audit log). TUI is the operator's observability
  surface; `web/` remains marketing + small fixtures only.
- Do NOT add new measurement semantics in the TUI layer. If the TUI
  surfaces a metric, grade_gates.py must already compute it. TUI ≠
  analytics product.

**Acceptance criteria**:
- TUI runs against live `~/.episteme/*.jsonl` streams without
  read-lock contention.
- Operator can derive Day-7 grading state in 30 seconds via TUI
  without running `grade_gates.py` manually.

### 3.7 Cross-project vision (v2.0 candidate)

**Maps to Job 2 + 3 at cross-project scale.** The operator's governing
intent includes "continuously update the framework" — today that's
per-project. v2.0 would consolidate protocol streams across multiple
projects so a protocol synthesized in project A surfaces as advisory
in project B when context-signature matches.

Scoped as v2.0 candidate because:
- Requires stable per-project framework format (v1.1 consolidation
  first).
- Raises privacy + trust questions not load-bearing in single-project
  v1.0 (cross-project context may leak local details).
- Needs cross-project hash-chain continuity — non-trivial.

Not executing this in v1.x explicitly — keeping it named so the
governing intent stays visible, but committing to the single-project
scope for v1.0 → v1.2.

---

## 4. Dependency graph — what blocks what

```
v1.0.0 GA (Day-7 branch 2.A)
    │
    ├─→ v1.0.1 Evidence Pipeline Hardening (§3.1)
    │      │
    │      ├─→ CP-FENCE-02 ✓ (Event 50)
    │      ├─→ CP-TEL-01 ✓ (Event 49)
    │      ├─→ CP-DEDUP-01 ✓ (Event 49) ──→ CP-DEDUP-02 retro cleanup
    │      ├─→ CP-CASCADE-01 (exempt state files) ──→ reduces own-noise
    │      ├─→ CP-CHKPT-01 (auto-checkpoint fix)
    │      └─→ CP-SMOKE-01 (plugin-install smoke test)
    │
    ├─→ v1.0.1 Schema Evolution (partial) (§3.2)
    │      ├─→ CP-SCHEMA-01a/b (enum additions)
    │      └─(CP-SCHEMA-02 + 03 defer to v1.1)
    │
    ├─→ v1.0.1 Behavior Knobs (partial) (§3.3)
    │      ├─→ CP-KNOBS-01 (autonomy_class wired)
    │      └─→ CP-KNOBS-02 (fence_check_strictness wired)
    │                │
    │                └─→ v1.1 Ashby + Jaynes build on these
    │
    └─→ v1.1 Framework Consolidation (§3.4)
           │
           ├─→ CP-SCHEMA-02 + 03 (from §3.2 deferred)
           ├─→ CP-DISC-02 (threshold re-calibration) ──→ unlocks Theme 5
           ├─→ CP-GRAPH-01 + 02 ──→ CP-GRAPH-03 (Recall@5)
           ├─→ CP-GUIDE-01 (cross-session guidance)
           ├─→ CP-RETRO-01 (retrospective sync-plan verification)
           │
           └─→ v1.2 Cognitive-Adoption Gates Raising (§3.5)
                  ├─→ CP-GATE-01..04 (raised bar + new gates)
                  │
                  └─→ v2.0 candidate: cross-project consolidation (§3.7)
```

Estimated execution calendar (assuming v1.0.0 GA Day-7 branch):

- v1.0.1-rc1 soak open: +10 days from GA
- v1.0.1 GA: +24 days from v1.0.0 GA (3-week sprint + 1-week soak)
- v1.1-rc1 soak open: +45 days from v1.0.0 GA
- v1.1 GA: +60 days
- v1.2-rc1: +90 days

Subject to operator-availability windows; calendar is best-case, not
commitment.

---

## 5. Appendix — Lessons from Hermes v2026.4.23 (Nous Research)

Hermes Agent v0.11.0 (2026-04-23) — published same day as our Event 38
soak anchor — shipped a major release with an Ink-based TUI, pluggable
transport layer, 5 new inference paths, expanded plugin surface, and
the `/steer` mid-run nudge command. Episteme uses Hermes as one of its
adapter targets (`src/episteme/adapters/hermes.py`), so their release
patterns are directly relevant to our v1.1 roadmap.

### 5.1 Adopt

- **Textual-based TUI (Hermes uses React/Ink)** — our equivalent
  stays Python-native (Textual library) to avoid a Node runtime
  dependency in core CLI. Scoped as CP-TUI-01 (§3.6). Features to
  mirror: status bar with stopwatch + git branch + session state;
  subagent spawn observability overlay (Task-tool integration);
  stable picker keys for reproducible flows.

- **`/steer`-style mid-run nudge** — Hermes `/steer <prompt>`
  injects a note the running agent sees after next tool call
  without breaking prompt cache. episteme equivalent:
  `episteme guide --inject <protocol-id>` operator command that
  appends a framework-protocol advisory to the agent's next
  PreToolUse payload. Aligns with Pillar 3 active guidance; maps
  to Job 3 (proactive guidance). Candidate v1.1 addition under
  Theme 4 as CP-GUIDE-02 (not yet in §3.4 — to be added if
  roadmap progresses past v1.0.1).

- **Observability overlay — subagent spawn tracing** — tracing
  Task-tool invocations as their own mini-sessions with surface
  + outcome per spawn is a natural fit for the Blueprint-D
  cascade detector. CP-TUI-02 in §3.6 (downgraded to v1.2-optional
  Event 53 — UI polish atop existing detector, not
  v1.1-load-bearing).

### 5.2 Consciously NOT adopt

- **Multi-provider LLM transport abstraction** — Hermes extracted
  `AnthropicTransport`, `BedrockTransport`, etc. into
  `agent/transports/`. Tempting to mirror, but episteme is a
  governance layer NOT a runtime; adding a transport abstraction
  is scope creep. Stay one layer up.

- **Messaging-platform expansion (QQBot, Telegram, Feishu, etc.)**
  — Hermes is a multi-platform agent gateway; episteme is not.
  Explicit non-goal.

- **Shell-script hooks generalization** — Hermes lets any shell
  script be a hook. We deliberately chose typed Python hooks
  with strict schemas for kernel discipline (see
  `kernel/CONSTITUTION.md`). Flexibility ≠ discipline; we chose
  discipline.

- **Provider-catalog live-discovery (GPT-5.5 via Codex OAuth)**
  — episteme doesn't maintain a model catalog; adapters cover
  the tool-ecosystem, not the provider ecosystem.

- **Plugin-packaged image_gen / TTS / STT backends** — out of
  product scope. episteme ≠ multi-modal orchestration layer.

### 5.3 Adoption matrix summary

| Hermes v0.11 feature | episteme decision | Milestone |
|---|---|---|
| Ink TUI | Adopt (Textual, Python-native) | v1.1 CP-TUI-01 |
| Subagent spawn overlay | Adopt (downgraded to optional Event 53) | v1.2 CP-TUI-02 |
| `/steer` mid-run nudge | Adopt (as `episteme guide --inject`) | v1.1 candidate |
| Transport ABC (multi-provider) | Explicit non-goal | — |
| Messaging platform expansion | Explicit non-goal | — |
| Shell-script hooks | Explicit non-goal | — |
| Provider-catalog live discovery | Explicit non-goal | — |
| Bundled image_gen / TTS plugins | Explicit non-goal | — |
| Plugin `transform_tool_result` / `dispatch_tool` | ~~Considered "study"~~ REMOVED Event 53 — vague, no CP id, no acceptance criteria. Positive-system rule: revisit only if a specific Pillar-3 advisory-injection pain-point surfaces. | — |

### 5.4 Counter-positioning observation

Hermes v0.11's release narrative centers on *surface expansion* —
more transports, more platforms, more plugin capabilities. episteme's
v1.0 → v1.2 narrative should center on *depth of epistemic
correctness* — more evidence pipeline hardening, more schema
fidelity, more gate-grading rigor. These are complementary products:
Hermes grows the surface; episteme grows the governance
underneath. The roadmap above should not chase Hermes's surface-
expansion tempo; stay true to the governance mandate.

### 5.5 Langfuse v3.170.0 — context

Langfuse (`langfuse/langfuse` · YC W23 · ~26k stars · TypeScript ·
self-hostable) describes itself as *"Open source LLM engineering
platform: LLM Observability, metrics, evals, prompt management,
playground, datasets."* v3.170.0 shipped 2026-04-23 (same day as
the Hermes release and our Event 38 soak anchor — which is
coincidental, but convenient: one clean reference date for all
three adjacent-ecosystem scans).

Langfuse's primary loop: app-developer instruments their LLM
integration → traces flow into Langfuse → scoring (manual or
programmatic LLM-as-judge) attaches to traces → datasets get
built from high-signal traces → prompt templates get versioned
against dataset benchmarks → playground lets operators compare
side-by-side.

Episteme's primary loop is **one layer up the stack**: an agent
(not a single LLM call) runs under governance; reasoning-surfaces
+ episodic records capture the decision substrate, not just the
prompt-completion pair; gate-grading is cognitive-adoption
measurement, not response-quality eval.

So the overlap is at **evidence-shape**, not at product category.
That shapes every adopt/decline call below.

### 5.6 Adopt (from Langfuse)

- **OpenTelemetry-compatible export for the evidence stream** —
  Langfuse integrates natively with OpenTelemetry's LLM semantic
  conventions. Episteme's episodic + framework + telemetry streams
  could emit OTel-compatible spans as an optional export format.
  Value: portability + interop with any OTel-compatible tool
  (Grafana, Jaeger, Datadog, Langfuse itself) without becoming an
  observability product ourselves. Maps to Job 4 (continuous
  self-maintenance: the ecosystem's tooling audits the kernel's
  own records). Candidate **v1.2 scope as CP-OTEL-01** (effort
  ~3 days; standardization not feature-expansion).

  **Scope discipline (added Event 53)**: export-only, one-way.
  No consumer UI. No Langfuse-specific integration code in the
  kernel. No new data model — map existing JSONL records to OTel
  spans. If OTel LLM semantic conventions change, the mapping
  layer is the only thing that updates. The moment this CP
  grows beyond "emit OTel spans on an `--otel-endpoint` flag,"
  it's scope creep and must be re-audited against the governance
  mandate.

- **Dataset-from-traces primitive** — Langfuse lets an operator
  promote selected traces into a dataset used for regression
  testing prompts. Episteme's analog: an `episteme dataset build`
  subcommand that promotes selected episodic records (operator
  spot-check "used" verdicts, or gate-grading PASS records, or
  specific context-signature clusters) into a versioned corpus
  for discriminator calibration + gate-grading regression. Maps
  directly to CP-DISC-02 (discriminator threshold re-calibration
  against larger corpus — §3.5 prerequisite). Candidate **v1.1
  scope as CP-DATASET-01** (effort ~2 days; operator-triggered
  workflow, not automatic).

- **Self-hostable + sovereignty stance** — Langfuse's self-host-
  first model aligns with episteme's Pillar 2 tamper-evident
  local-only semantics. No adopt needed — we already ship this.
  Noting as **parallel design philosophy** that validates our
  posture for external observers (reviewers, adopters) who
  understand Langfuse's positioning.

### 5.7 Consciously NOT adopt (from Langfuse)

- **Prompt management as a product feature** — Langfuse stores
  prompt templates, versions them, A/B-tests variants. Episteme
  is not a prompt-ops product. Our analog — the reasoning-surface
  schema — is load-bearing structure, not user-editable templates.
  Making reasoning-surfaces user-editable would collapse the
  governance contract. **Explicit non-goal.**

- **Playground / interactive exploration UI** — Langfuse's
  playground lets operators iterate prompts against live models.
  Episteme's analog would be "iterate on reasoning-surface fields
  against live agent runs" — but that's the agent itself doing
  the iteration, not a separate UI. Also the Textual TUI (§3.6
  CP-TUI-01) covers the observability side, not the interactive-
  exploration side. **Explicit non-goal.**

- **Multi-LLM-provider SDK abstractions** — Langfuse supports
  OpenAI SDK, Langchain, LlamaIndex, LiteLLM. Same rationale as
  the Hermes transport-ABC non-adopt (§5.2): we're governance,
  not runtime. Every SDK abstraction we add is scope creep away
  from the kernel mandate. **Explicit non-goal.**

- **Analytics-dashboard-as-primary-surface** — Langfuse's UI is a
  web dashboard for observability-first workflows. Episteme has
  a web/ surface today, but it's marketing-facing + a small
  fixtures visualization — not a general-purpose observability
  dashboard. The TUI (CP-TUI-01) + web dashboard parity
  (CP-WEB-01) stay **scoped to the kernel's own evidence
  streams**, not a general LLM observability product. The
  governance mandate would be diluted if we tried to become a
  Langfuse competitor. **Explicit non-goal at the product
  positioning level.**

### 5.8 Adoption matrix summary

| Langfuse v3.170 feature | episteme decision | Milestone |
|---|---|---|
| OpenTelemetry export | Adopt (portability, standardization) | v1.2 CP-OTEL-01 |
| Dataset-from-traces | Adopt (operator-triggered) | v1.1 CP-DATASET-01 |
| LLM-as-judge eval | ~~Adopt as secondary cross-check~~ REMOVED Event 53 — places an LLM inside the measurement apparatus; reintroduces confident-wrongness at the audit layer. Deterministic discriminator + human spot-check is the disciplined path. | — |
| Self-host-first sovereignty | Parallel design — already shipped | — |
| Prompt management | Explicit non-goal (would break governance contract) | — |
| Playground UI | Explicit non-goal | — |
| Multi-LLM SDK abstractions | Explicit non-goal (governance, not runtime) | — |
| Analytics-dashboard-as-product | Explicit non-goal (stay kernel-scoped) | — |

### 5.9 Counter-positioning observation (Langfuse)

Langfuse and episteme occupy **different layers of the agent
stack**, not different segments of the same layer:

- **Langfuse**: LLM-call observability + prompt-ops for app
  developers. "Is my LLM integration producing the right output?"
- **episteme**: Agent-reasoning governance for kernel architects.
  "Is the agent thinking in a way that would survive external
  audit?"

A team could (and should) use both simultaneously. Langfuse sees
the LLM call shape; episteme sees the reasoning shape around the
call. OpenTelemetry export from episteme → Langfuse could
literally federate the two: LLM-call observability in Langfuse,
cognitive-adoption governance in episteme, same underlying trace
standard.

This is the cleanest counter-positioning the roadmap has
surfaced so far: **Langfuse and episteme are vertically composable,
not horizontally competitive.** A v1.2 `CP-OTEL-01` makes this
composition explicit.

### 5.10 Cross-ecosystem pattern emerging

Two ecosystem scans in (Hermes §5.1-§5.4, Langfuse §5.5-§5.9) reveal
the same pattern repeating:

| Ecosystem | Their move | Our non-adopt rationale |
|---|---|---|
| Hermes | Multi-provider LLM transports | We're governance, not runtime |
| Langfuse | Multi-LLM SDK abstractions | Same |
| Hermes | Messaging platform expansion | Not our scope |
| Langfuse | Prompt management | Would break governance contract |
| Hermes | Shell-script hook flexibility | We chose typed Python for kernel discipline |
| Langfuse | Playground interactive UI | Not our product |

**Pattern**: every adjacent ecosystem expands its surface (providers,
platforms, modalities, UI richness). Episteme's opposite move —
deepening the governance underneath — is what makes the two
composable rather than competitive. This is not a reason to dismiss
ecosystem scans; it's a reason to keep doing them, because the
named non-adopts reinforce the governance mandate better than any
abstract statement would.

If a third ecosystem scan (e.g., next cadence) produces net-zero
adopt items, that's a signal: either the scan methodology is
over-fitting to our existing plans, or the ecosystem has genuinely
converged. In either case, re-evaluate whether quarterly cadence is
the right cadence.

---

## 6. How this doc stays current

- **Every Event that adds a CP** updates §3.1-§3.5 status columns.
- **Every v1.x GA** triggers a post-GA review: did the milestone
  theme acceptance criteria actually hold? Adjust next milestone
  accordingly.
- **Day-7 grading outcome** selects the executing branch (§2.A/B/C)
  and tightens §3 milestone effort estimates based on real
  evidence.
- **Quarterly** (≈ every v1.x GA): revisit §5 adjacent-ecosystem
  lessons — has Hermes / Claude Code / Codex shipped patterns
  worth adopting or explicitly declining?

If the operator intent (§0) shifts, this whole doc is deprecated and
rewritten goal-backward. The governing intent is the anchor; the
milestones are the implementation.

---

## 7. Audit log

This section records items that were considered for the roadmap but
removed on governance-mandate grounds. Preserves the reasoning so
future readers see the discipline, not a silent deletion. Every
removal must cite (a) which failure-mode / scope boundary it
conflicted with and (b) why a scoped-down variant wouldn't have
worked either.

### Event 53 audit (2026-04-24) — adjacent-ecosystem imports trimmed

Triggered by operator ask: *"is everything on
`docs/ROADMAP_POST_V1.md` really applicable to our product episteme?
If not delete, but yes since we got the ideas off from external
services, audit to make sure."*

Two removals, two scope tightenings, one vague-item deletion.

#### REMOVED · CP-DISC-03 (LLM-as-judge as secondary cross-check)

- **Source**: Langfuse §5.6 Event 52 adopt list.
- **Original rationale**: deterministic discriminator + LLM-judge
  disagreement as a threshold-calibration signal; framed as
  advisory-only, never replacing the deterministic path.
- **Why removed**: **places an LLM inside the measurement
  apparatus**. The kernel's mandate is anti-confident-wrongness;
  putting an LLM at the audit layer — even "advisory only" —
  means when the two signals disagree the operator has a fresh
  confident-wrongness-vs-deterministic adjudication on their
  hands instead of just reviewing flagged records themselves.
  The cognitive cost shifts from human-review-of-discriminator-
  output to human-review-of-LLM-review-of-discriminator-output,
  which is strictly worse.
- **Scoped-down variant wouldn't work**: any LLM participation in
  the measurement apparatus — even "audit 5 records per week" —
  reintroduces the failure mode. The correct path is:
  (i) operator manually reviews a sample of discriminator-flagged
  records; (ii) CP-DISC-02 recalibrates thresholds against that
  manual review. Human is already the judge; adding an LLM is
  subtractive.
- **Counter-factual preserved**: if post-v1.2 soak data reveals
  the deterministic discriminator has a FP/FN rate that human
  review cannot catch at scale, revisit with a specific failure-
  mode that would be countered — not with a speculative "might
  help."

#### REMOVED · CP-WEB-01 (Web dashboard parity)

- **Source**: Event 51 §3.6 cross-cutting TUI stream (I extrapolated
  from Hermes web-dashboard + subagent-overlay into a web-parity CP;
  it was my addition, not Hermes's).
- **Original rationale**: web dashboard for operator / team / external-
  reviewer audit of gate grading, framework protocols, fence pending
  state.
- **Why removed**: **soft-conflicts with our own §5.7 Langfuse non-
  adopt** ("analytics-dashboard-as-primary-product"). The TUI
  (CP-TUI-01) already covers the operator's observability use case on
  their own machine. Duplicating the surface on web starts us down
  the path of becoming a Langfuse-competitor — exactly the positioning
  we declined. External-reviewer audit as a *real* operator ask has
  never surfaced; building for a hypothetical is scope creep.
- **Scoped-down variant wouldn't work**: a minimal "one new route"
  addition still opens the slippery slope (first the route, then the
  filters, then the charts, then per-org auth...). Drawing the line
  at "TUI only" keeps the scope discrete.
- **Counter-factual preserved**: if external-reviewer audit becomes a
  real operator ask post-GA — cited by a specific operator or team —
  revisit as a standalone initiative with explicit "this is
  Langfuse-adjacent, here's the boundary" framing. Not as a
  sub-row in a TUI CP table.

#### DOWNGRADED · CP-TUI-02 (subagent-spawn observability overlay)

- **Source**: Hermes §5.1 Event 51 adopt (UI polish atop existing
  Blueprint D cascade detector).
- **Change**: v1.1 → **v1.2 optional**. Scope language tightened
  from "UI polish atop existing cascade detector" to an explicit
  lower-priority note.
- **Rationale**: CP-TUI-01 already surfaces the cascade detector's
  emissions in the TUI via existing streams. A dedicated subagent-
  spawn overlay is a visualization feature, not a measurement
  feature — shouldn't compete for v1.1 priority with Framework
  Consolidation (Theme 4) work that raises Gate 26 + 31 evidence
  quality.

#### TIGHTENED · CP-OTEL-01 (OpenTelemetry export)

- **Source**: Langfuse §5.6 Event 52 adopt.
- **Change**: explicit scope-discipline paragraph added in §5.6
  requiring export-only / one-way / no consumer UI / no Langfuse-
  specific integration / no new data model.
- **Rationale**: OTel export is strategically sound (portability,
  standardization) but the surface it opens — "episteme talks to
  observability tools" — can grow without discipline. Naming the
  boundary now prevents future scope drift.

#### REMOVED (vague-item) · Plugin `transform_tool_result` / `dispatch_tool` study

- **Source**: Hermes §5.1 Event 51 adopt ("study for Pillar 3
  advisory API").
- **Why removed**: no CP id, no effort, no acceptance criteria —
  violates the positive-system rule on rule-shape (every roadmap
  entry is a specific, enumerable commitment). "Study" items
  expand silently if not retired.
- **Counter-factual preserved**: if a specific Pillar 3 advisory-
  injection pain-point surfaces (e.g., adapter-layer needs
  `transform_tool_result` semantics for a concrete use case), open
  a CP then with named scope and effort.

### Cadence rule (Event 53 observation)

Two ecosystem scans in (Hermes Event 51 + Langfuse Event 52) + one
audit (Event 53) reveals a useful pattern: **the audit removes more
items than the scans add when the discipline is strict**. Event 52
added 3 adopts from Langfuse; Event 53 removed 1 + tightened 1 = 2
net changes against Event 52's additions. That ratio is healthy;
if future audits remove ≤ 25% of the prior scan's adopts, the
ecosystem scan methodology is over-permissive and the quarterly
cadence (§6) needs a tighter add-item bar. Track this ratio in
future Audit log entries.

---

## 8. Appendix — Lessons from Adjacent Ecosystems (Scan 3, Event 62)

Third quarterly-cadence ecosystem scan. Three repos surfaced in the
remaining-soak window (day 3.15/7) that occupy adjacent lanes to
episteme without competing on the load-bearing surface (file-system
intercept of state mutation + Reasoning Surface enforcement). Each
entry follows the §5 pattern: *what it does* → *Adopt* (specific
import tied to an existing kernel mechanism) → *Counter-positioning*
(why it doesn't compete with episteme's lane). All adoptions are
post-soak v1.0.1+ candidates per the operator's *do not touch the
hot-path or break the soak* discipline this Event respects by
construction.

### 8.1 `aldegad/alex-core-invariants` — policy repo enforcing 6 invariants

**What it does.** A small policy/governance repository whose load-
bearing artifact is a curated set of six invariants the maintainer
considers non-negotiable for any project they own. Each invariant is
named, scoped, and accompanied by a structural enforcement
mechanism (typically a git hook or CI rule). The repo is itself the
governance surface; downstream projects import the invariants by
reference.

**Adopt.** Two specific imports tied to existing episteme mechanisms:

- **`No Silent Fallback` rule → backs Blueprint D (Architectural
  Cascade & Escalation).** The rule is a structural prohibition
  against the cheapest-local-patch pattern: when a flaw is
  discovered mid-work, the agent must NOT silently swap in a
  fallback path that papers over the discovery. This is the same
  discipline Blueprint D enforces via patch-vs-refactor evaluation
  + symmetric cascade synchronization + deferred-discovery logging.
  Adopting `No Silent Fallback` as a named protocol-class entry in
  `~/.episteme/framework/protocols.jsonl` (post-soak, when the
  protocol stream materializes) gives Blueprint D an externally-
  validated articulation of its own anti-pattern. Cross-reference:
  `docs/DESIGN_V1_0_SEMANTIC_GOVERNANCE.md` § Blueprint D · sync_plan
  + deferred_discoveries discipline.

- **`SHA-Pinned Guard` git hook → protect `kernel/*.md` + README
  translations from silent drift.** A pre-commit / pre-push hook
  that compares declared SHA hashes of named files against working-
  tree SHAs and refuses if any drift is detected without an
  accompanying CHANGELOG entry. Adoption candidate as
  `core/hooks/sha_pinned_guard.py` (post-soak v1.0.1+ CP
  CP-SHAGUARD-01). Importantly, this **complements** rather than
  duplicates the existing `kernel/MANIFEST.sha256` discipline:
  MANIFEST covers kernel-binary integrity (load-time verification);
  SHA-Pinned Guard covers commit-time enforcement on docs +
  translations (preventing silent drift in user-facing surfaces).
  The two operate at different lifecycle stages and reinforce each
  other.

**Counter-positioning.** alex-core-invariants enforces *static*
invariants as policy: the rule set is fixed, the violation is
binary, the enforcement is at git-hook commit time. Episteme
enforces *dynamic causal-consequence modeling*: the Reasoning
Surface protocol forces the agent to construct a falsifiable causal
model BEFORE state mutation; the validation depth is
context-conditional (per Cognitive Blueprint A/B/C/D); the
enforcement is at file-system interception of state mutation. The
two operate at structurally different abstraction levels — policy
checks vs. cognitive contract — and are complementary supplements
rather than competitors. Episteme could import alex-core-invariants
patterns as a thin policy layer above its own cognitive contract;
alex-core-invariants cannot import episteme's full discipline
without becoming episteme.

### 8.2 `asgeirtj/system_prompts_leaks` — archive of leaked corporate system prompts

**What it does.** An archive repository collecting publicly-leaked
system prompts from commercial AI agents (Claude.ai, ChatGPT,
GitHub Copilot, Cursor, etc.). Each leaked prompt is preserved
verbatim in a dated subdirectory with provenance metadata. The
repository's value is purely documentary — it does not propose
patterns, judge them, or offer enforcement mechanisms.

**Adopt.** One specific import tied to the hot-path normalizer:

- **Bypass-vector vocabulary mining for the hot-path Reasoning
  Surface validator.** The leaked prompts reveal the standard
  XML/structural patterns commercial agents use to organize
  reasoning (e.g., `<thinking>`, `<plan>`, `<task>`, `<tool_use>`,
  `<reflection>` tag conventions). A sufficiently aware agent could
  attempt to bypass episteme's hot-path validator by emitting
  fluent-vacuous content INSIDE these XML structures — the structures
  themselves carry no falsifiability, and a naive validator might
  accept them as "structured reasoning" without the Reasoning
  Surface's falsifiable-disconfirmation requirement. Adoption
  candidate as a vocabulary expansion to `core/hooks/reasoning_surface_guard.py`
  normalizer (post-soak v1.0.1+ CP CP-NORM-EXPAND-01): scan agent-
  authored content for these XML-structural patterns and apply the
  Reasoning Surface validity requirements to their contents. Cross-
  reference: `kernel/REASONING_SURFACE.md` § Validity rules + lazy-
  token blocklist.

  **Asymmetric-information discipline.** The kernel never publicly
  documents *which specific* bypass patterns it detects. This is
  load-bearing: a publicly-enumerated detection list becomes a
  publicly-enumerated avoidance list for sufficiently-aware
  attackers. The CP-NORM-EXPAND-01 implementation lives in
  `core/hooks/` (governance-class); the public face documents only
  that the normalizer covers commercial-agent XML-tag patterns,
  without naming the patterns.

**Counter-positioning.** system_prompts_leaks confirms one of
episteme's load-bearing theses by documentary contrast: **system
prompts are not guardrails; they are documentation with personality.**
Every leaked prompt in the archive can be skipped, ignored, or
silently overridden by the agent's actual generation behavior — the
prompt-as-instruction model has no enforcement teeth. Episteme's
file-system hook layer is the structural answer: a hook that exits
non-zero cannot be persuaded out of refusing the op. The archive is
useful precisely because it documents the failure mode episteme
exists to prevent. The repo is not a competitor; it is supporting
evidence for episteme's core architectural choice (file-system
interception over prompt instruction).

### 8.3 `refactoringhq/tolaria` — files-first markdown knowledge app

**What it does.** A personal-knowledge-management application
designed around the principle that markdown files on disk are the
canonical knowledge surface, with the application UI as a thin
rendering layer. The load-bearing discipline is *Convention over
Configuration* applied via strict YAML frontmatter on every markdown
note: required fields, controlled vocabularies, and structural
contracts that enable deterministic rendering, search, and
cross-reference.

**Adopt.** One specific import tied to the framework rendering layer:

- **Stricter row-shape conventions for `~/.episteme/framework/`
  JSONL streams** parallel to tolaria's YAML-frontmatter discipline.
  Currently `protocols.jsonl` and `deferred_discoveries.jsonl` use
  the `cp7-chained-v1` envelope with required fields enforced at
  write time, but the convention is implicit in the writer code
  (`core/hooks/_framework.py`) rather than declared as a versioned
  schema contract. Adoption candidate (post-soak v1.0.1+ or v1.1):
  formalize the JSONL row-shape as a versioned JSON schema under
  `core/schemas/framework/*.json`, with writer-side validation
  + reader-side parser tolerance for forward-compatible schema
  evolution. The motivating downstream use-case: future TUI or
  dashboard surfaces (mentioned in `docs/POST_SOAK_TRIAGE.md`
  context) need predictable row shapes to render without ad-hoc
  per-renderer parsing. Cross-reference: `docs/MEMORY_CONTRACT.md`
  schema discipline as a parallel pattern.

  **Structural difference acknowledged.** tolaria's frontmatter
  discipline applies to *markdown* (a row-of-records convention
  implicit in the markdown itself); episteme's adoption applies to
  *JSONL* (one structured record per line). The translation is the
  *convention-over-configuration* principle, not the literal
  syntactic shape: required fields + controlled vocabulary +
  versioned schema, regardless of file format.

**Counter-positioning.** tolaria operates at the *personal
knowledge management* lane: an individual's accumulated notes,
linked manually, rendered for the individual's recall. Episteme
operates at the *governance kernel* lane: structural enforcement
across multiple AI agents and tools, with tamper-evident chained
provenance, validating *cognitive contract compliance* at the
moment of state mutation. The two lanes do not compete — tolaria
augments human memory; episteme governs agent reasoning. The shared
*files-first* conviction (markdown / JSONL on disk as canonical,
UI as renderer) is structurally analogous, which is why the
convention discipline is a clean import. tolaria's UI patterns,
search semantics, and personal-knowledge-graph features are NOT
adoption candidates — they're orthogonal product surface.

### Cadence-rule projection (Event 62)

Per the §6 quarterly cadence and the §5 audit-removal-ratio
heuristic, this scan adds three adopts (one per repo). The
companion audit pass (whenever it runs) should remove ≥ 1 if the
discipline is strict. Track in the next Audit log entry.

# Phase 6x: Additional-Alphabet Quantum-Compiler Instantiations + Mathlib Upstreaming

## Technical Roadmap — May 2026

*Prepared 2026-05-25 PM, following Phase 6u close (alphabet-independent generic Solovay-Kitaev substrate + Clifford+T instance shipped UNCONDITIONAL; commits `7ad8e55` through `137838e`; see `docs/roadmaps/Phase6u_Roadmap.md` for closure summary).*

---

> ## 🔄 RETROSPECTIVE ADDENDUM — 2026-05-26 PM (Lift/Shift Reframing)
>
> The original Phase 6x roadmap (below, as Sections "Track catalog" through "Cross-references") scoped T-A1 (trapped-ion) and T-A2 (Clifford+CCZ) as **full multi-qubit SU(d > 2) compilation** ships, with the SU(d) substrate extension under T-A2.0 estimated at ~1,000-2,000 LoC and the aggregate Phase 6x effort at multiple thousand LoC. The Phase 6x first-session ship (2026-05-26 AM) yielded heavily on this substrate (T-A1.{3,4,5} + T-A2.0 + T-A2.{1..5}) under a misapplication of the Invariant #15 pivot rule (yielded on "substantial work" grounds when the pivot rule's literal scope is "yield only when an axiom would be required").
>
> The retrospective audit (2026-05-26 PM) reframed Phase 6x along a **lift/shift, recycle-and-grow** interpretation that reuses the Phase 6u SU(2)-targeted substrate verbatim:
>
>   - **T-A1 lift/shift framing**: ship "1Q-rotations-on-each-ion compiled via Phase 6u Clifford+T substrate + MS(θ) emitted as primitive token." Matches how Quantinuum / IonQ production compilers actually work (MS is the physically-realized entangling primitive, not something compiled into 1Q gates). ~200-400 LoC, *not* ~1,200-2,500. The "full SU(4) compilation" is academic-completeness work *deferred to Phase 6y Track T-A1′*.
>
>   - **T-A2 lift/shift framing**: ship "CCZ-matrix substrate + CCZ-as-primitive interpretation" with the full SU(8) Clifford+CCZ compilation explicitly deferred to Phase 6y Track T-A2′. ~100-300 LoC at Phase 6x; the substantive SU(8) compile chain ships in Phase 6y after Track S (SU(d) extension).
>
>   - **M.1, M.2, M.4 ACTUAL EXTRACTION**: the Phase 6x first-session ship shipped Mathlib-PR-quality *aliases* rather than the de-privatized extracted lemmas the roadmap targeted. Phase 6x completion (this revised roadmap) ships the actual de-privatization + generic-type-parametrization + Mathlib filename submission targets, ~100-300 LoC of submission-step work per track.
>
>   - **T-S′ Ross-Selinger algorithmic refinement**: the Phase 6x first-session ship was *existential* (finite-Finset cover) rather than the *algorithmic* (Ross-Selinger ℤ[ω][1/√2] symbolic enumeration) the roadmap targeted. The algorithmic refinement is the actual deliverable; ships in this completion phase with a Lit-Search task drop if necessary.
>
>   - **M.4 headline-level integration**: the Phase 6x first-session ship shipped the per-step recurrence at cliffordTGeneratingSet only. The actual roadmap deliverable is the headline-level length conjunct `(compile U ε).toWord.length ≤ skLength (skLevel_polylog ε)` integrated into all per-alphabet T-X.5 headlines. Ships in this completion phase.
>
> The Phase 6y roadmap (`docs/roadmaps/Phase6y_Roadmap.md`) captures the SU(d > 2) academic-completeness work that the Phase 6x lift/shift framing now explicitly defers. The remaining Phase 6x work + Phase 6y together cover what the original Phase 6x roadmap (below) scoped.
>
> **Anti-patterns identified for the Phase 6x completion + Phase 6y consumers** (to avoid repeating):
>
>   1. **Pivot Rule #15 mis-scoping**: yielding on "substantial work" rather than "axiom required." The pivot rule fires ONLY when shipping would require an axiom. Substantial-but-doable multi-session work = ship it across multiple sessions; don't yield.
>   2. **Heavy-interpretation default**: when the roadmap presents architectural options, check whether a LIGHTER interpretation gives the same audience-relevant claim. Don't pick the heaviest by default.
>   3. **Alias-only Mathlib PRs**: the Mathlib-PR deliverable is the de-privatized, generic-typed, docstring-equipped extracted lemma. A renaming alias of the existing project lemma is NOT a Mathlib PR.
>   4. **Substrate-only-shipped vs. headline-integrated**: per-step lemmas need to integrate into HEADLINE theorems for downstream consumption. Stopping at substrate is incomplete.
>   5. **Existential vs. algorithmic**: when the roadmap calls for "genuinely runnable" / "algorithmic" / "constructive," existential proofs do not satisfy the deliverable.
>
> The retrospective is documented in full at `docs/stakeholder/Phase6x_Implications.md` + `docs/stakeholder/Phase6x_Strategic_Positioning.md`.

---

**Trigger condition:** Phase 6u shipped the alphabet-independent `GeneratingSet` substrate (Waves 1–6 + Wave 4b) and validated it via the Clifford+T instance (Track T-S). The Lie-algebraic core (Dawson–Nielsen recursion, Cartan v4 closed-subgroup classification, BCH bracket-closure, ε₀-net, super-quadratic discharge) is fully generic. Phase 6x picks up the additional-alphabet instantiations that were re-slotted from Phase 6u (per ADR 008: T-A1/T-A2/T-B do not fit Phase 6v/6w scope) **plus** three Mathlib-upstream-PR-quality lemma extractions identified in the Phase 6u Strategic Positioning memo.

**Headline goal:** ship 3 additional alphabet instantiations on the Phase 6u substrate (Read-Rezayi `SU(2)_k` for `k ∈ {5, 7}` as Tier B; Clifford+CCZ as Tier A2; trapped-ion MS+1Q as Tier A1) **plus** 3 Mathlib upstream contributions extracting generic SU(2)-Lie-group infrastructure currently sitting inside the FKLW substrate. The per-alphabet work budget is ~few hundred to ~1000 LoC per Phase 6u Strategic Positioning's empirical pattern (vs. the multi-thousand-LoC original Phase 6t Fibonacci ascent), with the largest cost component being the per-alphabet density proof tackled in 1–3 sessions following the Niven-based template.

**Predecessor:** Phase 6u (`docs/roadmaps/Phase6u_Roadmap.md`). Phase 6x is **alphabet-instance + community-citizenship work**; no new generic-substrate refactoring required. Track T-A2's "SU(8) substrate extension" sub-track is the one exception — it requires extending the SU(2)-targeted substrate to higher-rank, which IS substrate work but is alphabet-driven (not a general refactor).

**Project rule applied:** No new project-local axioms (Pipeline Invariant #15 RESPECTED). No `maxHeartbeats` overrides in proof bodies (Invariant #10). Standard kernel only on headlines.

---

> **AGENT INSTRUCTIONS — READ BEFORE ANY PHASE 6x WAVE WORK:**
>
> 1. **Mandatory project bootstrap** per workspace `CLAUDE.md` Mandatory References list.
> 2. **Read `Phase6u_Roadmap.md` end-to-end** — Phase 6x's track instantiations follow the Phase 6u Track T-S (Clifford+T) template directly. The 5-sub-wave alphabet pattern (T-X.1 gen set + T-X.2 closure-density witness + T-X.3 ε₀-net + T-X.4 calibration + T-X.5 headline) was established there.
> 3. **Read `Phase6u_Implications.md` + `Phase6u_Strategic_Positioning.md`** in `docs/stakeholder/` for the per-track audience positioning, Mathlib-upstream rationale, and the Niven-based density methodology template.
> 4. **Critical substrate — read source directly:**
>    - **Boykin–Mor–Pulver–Roychowdhury–Vatan 1999** (`arXiv:quant-ph/9906054`) for the Niven-based template (now formalized for Clifford+T in `CliffordTInfiniteOrder.lean`).
>    - **Mathlib4 `NumberTheory.Niven`** (`Mathlib/NumberTheory/Niven.lean`) — `Real.isIntegral_two_mul_cos_rat_mul_pi`, `niven`, plus the `Real.isAlgebraic_cos_rat_mul_pi` / `Complex.isAlgebraic_cos_rat_mul_pi` family.
>    - **Read-Rezayi 1999** (`arXiv:cond-mat/9809384`) for the `SU(2)_k` anyon model substrate.
>    - **Kliuchnikov–Maslov–Mosca 2013** (`arXiv:1206.5236`) + **Ross-Selinger 2014** (`arXiv:1403.2975`) for exact Clifford+T synthesis (relevant if Phase 6x ships a constructive ε₀-net follow-on).
>    - **Phase 6u substrate**: `lean/SKEFTHawking/FKLW/Generic*.lean` (7 files, ~2,400 LoC) — the entire alphabet-agnostic chain.
>    - **Phase 6u Clifford+T instance**: `lean/SKEFTHawking/FKLW/CliffordT*.lean` (8 files, ~1,460 LoC) — the canonical first instance template for any new alphabet.
> 5. **Do not delegate substantive theorem proving to subagents** for the load-bearing density-proof sub-waves. MCP loop default; Aristotle is fallback. Background agents OK for substrate refactoring + composition work.
> 6. **No PM / time estimates anywhere** — by user direction.
> 7. **Pivot rule:** if a Wave's closure-density witness for a target alphabet requires a tracked Prop or a Mathlib-substrate-not-present-in-v4.29.1 substrate piece (e.g., the SU(d) Cartan classification for Track T-A2), YIELD for user sign-off per Pipeline Invariant #15. Do NOT ship a project-local axiom.

---

## Track catalog

Four primary tracks, organized by per-track substrate-reuse level (highest reuse first) and audience priority:

  - **Track T-B (Read-Rezayi `SU(2)_k`)**: highest-substrate-reuse (target group remains SU(2); only generators change). Multiple instances (k ∈ {5, 7}) share substrate. Topological-QC-research audience.
  - **Track T-A1 (Trapped-ion native gates)**: medium-substrate-reuse (requires discretization layer + target-group decision: SU(2) restriction vs. SU(4) extension). Industry-quantum-compiler audience (Quantinuum, IonQ).
  - **Track T-A2 (Clifford+CCZ at SU(8))**: lowest-substrate-reuse (requires substantive SU(2)→SU(d) substrate extension, ~1,000-2,000 LoC). Fault-tolerant-architecture-research audience.
  - **Track M (Mathlib upstreaming)**: independent of T-B/T-A1/T-A2; can run in parallel. Community-citizenship.

**Status legend** (matches Phase 6u):
- ✅ **SHIPPED** — Lean / numerical deliverables committed and kernel-verified.
- 🟡 **IN-PROGRESS** — partial deliverables shipped.
- 📝 **WORKING DOC** — Stage-1 substrate-analysis or audit draft only.
- ⏳ **NOT STARTED**.

| Track | Codename | Status | Bundle absorption |
|---|---|---|---|
| **Track T-B (Tier B)** | Read-Rezayi `SU(2)_k` instances for `k ∈ {5, 7}` — next-universal-anyon family beyond Fibonacci (`k = 3`). Highest substrate-reuse: ~80-90% of Phase 6t Fibonacci substrate transfers near-mechanically with σ_k generators replacing σ_Fib. Density via Niven-style on the per-`k` trace identity. | ✅ SHIPPED 2026-05-26 PM (T-B.5 + T-B.7 UNCONDITIONAL bundled-strict headlines) | D4 §9.8 (Read-Rezayi-extended multi-alphabet showcase) |
| **Track T-A1 (Tier A) — LIFT/SHIFT** | Trapped-ion native gate set under the **production-aligned reading**: 1Q rotations compiled via Phase 6u Clifford+T substrate; MS(θ) as primitive token (not compiled). Full SU(4) compilation deferred to Phase 6y Track T-A1′. | 🟡 SUBSTRATE SHIPPED 2026-05-26 PM (MS matrix + grid); chain integration pending Phase 6x completion | D4 §9.8 + E1 polariton/trapped-ion cross-bridge |
| **Track T-A2 (Tier A) — ALPHABET SUBSTRATE** | Clifford+CCZ matrix definition substrate at SU(8); CCZ-as-primitive interpretation. Full SU(8) Clifford+CCZ compilation deferred to Phase 6y Track T-A2′ (requires Phase 6y Track S SU(d) substrate extension as prerequisite). | ✅ SHIPPED 2026-05-26 PM (CCZ matrix + diagonal identities) | D4 §9.8 (substrate-level showcase entry; full-compile entry via Phase 6y) |
| **Track M (Mathlib upstream)** | Three lemma extractions from FKLW substrate to Mathlib4 PR-quality: (M.1) Generic BCH order-2 cubic bound; (M.2) Generic Cartan v4 density-from-witness; (M.3) three-direction-product strict differentiability. **ACTUAL EXTRACTION required** (not alias-only): de-privatized + generic-typed + Mathlib filenames. | 🟡 PR-PRESENTATIONS SHIPPED 2026-05-26 PM (M.3 NO-OP confirmed); actual extractions pending Phase 6x completion | (Mathlib4 upstream; no project-bundle absorption) |
| **Track T-S′ (Constructive ε₀-net)** | Replace Phase 6u T-S `Classical.choose`-based ε₀-net with Ross-Selinger 2014 `ℤ[ω][1/√2]` symbolic enumeration. **Genuinely runnable** required (not just existential). | 🟡 EXISTENTIAL FINITE-FINSET COVER SHIPPED 2026-05-26 PM; algorithmic Ross-Selinger refinement pending Phase 6x completion (Lit-Search task drop in scope) | (Compiler-side strengthening) |
| **Track M.4 (Concrete-word length-bound)** | Tighten T-S.5 length conjunct from abstract `skLength` to concrete `(compile U ε).toWord.length ≤ skLength (skLevel_polylog ε)`. **Headline-level integration** at all GeneratingSet instances required. | 🟡 PER-STEP RECURRENCE SHIPPED AT CLIFFORDT 2026-05-26 PM; headline-level integration + per-alphabet specializations pending Phase 6x completion | (Compiler-side strengthening) |

**Track dependencies:**
- T-B, T-A1, T-A2, and M can all run **in parallel** — they touch disjoint files/areas of the Phase 6u substrate.
- T-A2 has an internal dependency: T-A2.0 (SU(d) substrate extension) must precede T-A2.1–T-A2.5 (instantiation sub-waves).
- Track M's three lemmas can each be shipped independently. M.1 and M.2 are extract-and-generalize work; M.3 may already be complete in the technique sense (the existing private lemma in `SU2BCHBracketClosure.lean` is the SU(2) specialization; if the generic technique is what's wanted, the work is bounded to de-privatize + generalize the type).
- All tracks can run after Phase 6u substrate (already shipped). No cross-track dependencies.

---

## Track T-B detail — Read-Rezayi `SU(2)_k` for `k ∈ {5, 7}` (Tier B)

### Goal

Instantiate the Phase 6u substrate at the next universal Read-Rezayi anyon levels beyond Fibonacci (`k = 3`). Each `k ∈ {5, 7}` (and potentially `k ∈ {11, 13, …}` future) gets the bundled-strict quantitative Solovay-Kitaev headline at the `SU(2)_k` braiding representation.

### Key advantage

**Highest substrate-reuse of all the Phase 6x tracks (~80-90% direct transfer).** Target group remains SU(2); only the generators change. The Phase 6t Fibonacci-specific machinery transfers near-mechanically with σ_k generators replacing σ_Fib generators. The Cartan v4 closed-subgroup classification is unchanged (still SU(2)). The BCH cubic bound + Y_h Lipschitz + super-quadratic recursion are all reusable verbatim.

### Per-`k` sub-wave decomposition (mirrors Phase 6u Track T-S)

**T-B.k.1 — Generators** (~50-100 LoC per `k`). Define `σ_k_1, σ_k_2 ∈ SU(2)` for the SU(2)_k braid representation. The 2-strand representation of `B_n` at SU(2)_k generates a subgroup of SU(2) with explicit closure structure (Jones-Wenzl projectors, F-symbols computable from the SU(2)_k quantum-group data already shipped in `SKEFTHawking.SU2kMTC.lean` / `SU2kSMatrix.lean`).

**T-B.k.2 — Closure-density witness** (~150-300 LoC per `k`). Replicate the Phase 6u Niven-based density template with σ_k generators. The non-cyclotomic-trace argument differs per `k`:
- For `k = 3` (Fibonacci): trace involves golden-ratio quantities (already done in Phase 6t / 6p via Cartan v4).
- For `k = 5`: trace involves `2cos(πj/(k+2))` quantities for various `j`; for `k = 5` this is `2cos(πj/7)`. Niven-style obstruction: verify the trace's minimal polynomial is not of cyclotomic form.
- For `k = 7`: analogous with `2cos(πj/9)`.

**T-B.k.3 — ε₀-net** (~50-100 LoC per `k`). Existential via Classical.choose from Wave 2 density (mirrors Phase 6u Track T-S.3). Constructive form (Ross-Selinger-style symbolic enumeration on the SU(2)_k algebraic-number-theoretic structure) deferred.

**T-B.k.4 — Calibration** (~5-10 LoC per `k`). Immediate via Wave 4b's `SkApproxCSuperQuadraticBound_generic_holds`.

**T-B.k.5 — Bundled-strict headline** (~50-100 LoC per `k`). Direct instantiation of the Wave 6 generic headline at the per-`k` `GeneratingSet`. Conditional only on the per-`k` density witness, which T-B.k.2 discharges.

### Aggregate Track T-B effort

~400-800 LoC per `k`; multiple `k` values can be shipped in sequence. `SU(2)_5` alone: ~500 LoC.

### Audience and bundle absorption

**Audience**: topological-quantum-computing researchers in the Freedman-Kitaev-Larsen-Wang lineage; Read-Rezayi 1999 / Nayak-Simon-Stern-Freedman-Das Sarma 2008 review community; fault-tolerant-architecture researchers comparing topological vs. fault-tolerant resource costs.

**Bundle absorption**: D4 §9.8 — extend the multi-alphabet showcase from {Fibonacci, Clifford+T} to {Fibonacci, Clifford+T, RR `k=5`, RR `k=7`}.

### Risk

LOW per `k`. The Phase 6u Fibonacci-template transfer is well-validated by the Clifford+T instance.

---

## Track T-A1 detail — Trapped-ion native gate set (LIFT/SHIFT FRAMING; full SU(4) → Phase 6y)

### Goal

Instantiate the Phase 6u substrate at the Quantinuum / IonQ native gate set: Mølmer-Sørensen MS(θ) + arbitrary 1Q rotations. **Lift/shift framing (the Phase 6x completion target)**: kernel-verify the **per-ion 1Q-rotation compilation** via the Phase 6u Clifford+T substrate, with MS(θ) emitted as a primitive token (not compiled into 1Q gates). This matches how Quantinuum H1, IonQ Aria, and AQT production compilers actually work — MS is the physically-realized entangling primitive, not something the compiler decomposes.

### Key distinction (clarified per 2026-05-26 PM retrospective)

The original roadmap (above) presented T-A1.2 as a three-way decision: (a) 1Q-only-no-MS, (b) extend substrate to SU(4), (c) KAK decomposition. The retrospective reframing reads option (a) **NOT** as "ignore MS entirely" (commercially useless) but as **"1Q-compiled + MS-primitive"** — the production-aligned interpretation. The full SU(4) compilation (original options (b) + (c)) is academic-completeness work deferred to Phase 6y Track T-A1′.

### Sub-wave decomposition (lift/shift framing)

**T-A1.1 — Trapped-ion alphabet skeleton** (~100-200 LoC). Define `trappedIonGeneratingSet : GeneratingSet` with:
  - Word type `W := FreeGroup ((Fin n_ions) × Fin 2 ⊕ MSPrimitiveToken)` where `MSPrimitiveToken` encodes the MS(θ) gates at rational-π/N grid.
  - Representation `ρ_hom` mapping `(ion_i, j) ↦ <per-ion 1Q gate at index j on ion i>` and `MS_θ ↦ MSGateMat(θ)`.
  - Generator set: H_SU and T_SU lifted per-ion + MS primitives.

The substrate skeleton already shipped in Phase 6x first session (`TrappedIonAlphabet.lean`) — MS matrix + grid + identity sanity-checks.

**T-A1.2 — Per-ion 1Q-compilation reduction** (~100-200 LoC). Show that any unitary acting non-trivially on a single ion's 1Q subspace decomposes into a product of `H_SU` and `T_SU` operators on that ion via the Phase 6u Clifford+T substrate (`cliffordTGeneratingSet` directly applies). The reduction is essentially a re-indexing: each per-ion 1Q rotation compile-call invokes Phase 6u verbatim.

**T-A1.3 — ε₀-net at the per-ion level** (~30-50 LoC). Phase 6u Wave 3's ε₀-net composed with `trappedIonGeneratingSet`'s per-ion 1Q substructure. Existential (Classical.choose) or constructive (Phase 6x T-S′ finite-Finset cover) — either is acceptable per the trapped-ion lift/shift framing.

**T-A1.4 — Calibration via Phase 6u Wave 4b** (~30-50 LoC). Direct instantiation; no new analytic work.

**T-A1.5 — Bundled-strict headline** (~50-100 LoC). The per-ion-1Q-compile bundled-strict headline at `trappedIonGeneratingSet`. Statement form: for any U ∈ SU(2) (single-ion target) and ε ∈ (0, ε₀], the compiled trapped-ion word approximates U to error ≤ ε at length ≤ polylog(1/ε) — with the MS(θ) primitives passed through unchanged.

### Aggregate Track T-A1 effort (lift/shift framing)

~250-400 LoC across ~1-2 sessions (Phase 6x completion). The substrate skeleton is already shipped; the remaining work is the re-indexing + headline integration.

### Deferred to Phase 6y Track T-A1′ (academic completeness)

The full SU(4) compilation (where MS(θ) is in the discrete alphabet and the compiler decomposes any 2-qubit unitary into MS + 1Q sequences) requires the Phase 6y SU(d) substrate extension. ~600-1,100 LoC across 2-4 Phase 6y sessions.

### Audience and bundle absorption

**Audience**: industry quantum-compiler teams at Quantinuum, IonQ, AQT, Universal Quantum; trapped-ion-architecture-research community. The lift/shift framing addresses the per-ion 1Q compilation that production code needs verified; the full SU(4) academic-completeness ship (Phase 6y) addresses the verified-compiler-for-arbitrary-2-qubit-gates narrative.

**Bundle absorption**: D4 §9.8 + E1 (Paris-LKB polariton experimental letter cross-bridge — the trapped-ion and polariton communities share gate-set discretization concerns).

### Risk (lift/shift framing)

LOW. The lift/shift framing is mostly re-indexing of the Phase 6u Clifford+T substrate; no new analytic work.

---

## Track T-A2 detail — Clifford+CCZ alphabet substrate (FULL SU(8) → Phase 6y)

### Goal (Phase 6x scope after retrospective reframing)

Ship the **Clifford+CCZ alphabet substrate** at the matrix-definition level: `CCZ_mat : Matrix (Fin 8) (Fin 8) ℂ` with explicit diagonal-entry verification (`CCZ_mat_apply_7_7 = -1`, `CCZ_mat_apply_diag_ne_7 = 1` for `i ≠ 7`). This is the in-scope deliverable for Phase 6x — already shipped in Phase 6x first session (`CliffordCCZAlphabet.lean`).

The **full SU(8) compilation** (`U ∈ SU(8) → Clifford+CCZ word with ε-error + polylog length`) is the academic-completeness work deferred to **Phase 6y Track T-A2′** because:

  - The Phase 6u SU(2)-targeted substrate does not directly compile arbitrary SU(8) unitaries.
  - The Phase 6y Track S (SU(d > 2) substrate extension) is the prerequisite for any SU(8) compilation ship.
  - Treating CCZ as a *primitive token* in Phase 6x (analogous to MS(θ) in T-A1 lift/shift) doesn't yield a non-trivial verified ship because Cliffords are EXACT (no SK approximation needed) — the SK compilation only kicks in when arbitrary SU(8) is the target.

### Phase 6x completion deliverables (this revised scope)

Already shipped in Phase 6x first session — no additional T-A2 work required at the Phase 6x scope:

  - `CCZ_mat` matrix definition.
  - `CCZ_mat_apply_7_7 : CCZ_mat ⟨7, _⟩ ⟨7, _⟩ = -1`.
  - `CCZ_mat_apply_diag_ne_7 : ∀ i, i ≠ ⟨7, _⟩ → CCZ_mat i i = 1`.

### Deferred to Phase 6y Track T-A2′ (academic completeness)

Per Phase 6y Roadmap §"Track T-A2′ detail":

  - SU(8) `GeneratingSet` instance consuming Phase 6y Track S substrate.
  - Clifford+CCZ closure-density at SU(8) (~400-700 LoC).
  - ε₀-net + calibration + bundled-strict headline at SU(8) (~300-600 LoC).

Aggregate Phase 6y T-A2′ effort: ~700-1,300 LoC across 3-5 Phase 6y sessions.

### Audience and bundle absorption

**Audience**: fault-tolerant-architecture researchers (Litinski, O'Gorman, Babbush, Beverland); magic-state-distillation researchers.

**Bundle absorption**: D4 §9.8 — multi-alphabet showcase. The Phase 6x in-scope ship adds CCZ as the substrate-level entry; the Phase 6y T-A2′ ship adds Clifford+CCZ as the full-compile entry.

### Risk

Phase 6x scope: LOW (already shipped).
Phase 6y T-A2′ scope: MEDIUM, addressed in Phase 6y Roadmap.

---

## Track M detail — Mathlib4 upstream contributions

### Goal

Extract three generic SU(2)-Lie-group / matrix-Lie-theory lemmas currently sitting inside the FKLW substrate to Mathlib4-upstream-PR-quality form. These are **Phase 6s Track 2 (community-citizenship)** style work — strengthening Mathlib4's coverage in ways that benefit the broader formal-methods community.

### M.1 — Generic BCH order-2 cubic bound

**Statement (to ship in Mathlib upstream form)**:

> *For any complex matrix Lie algebra `𝔤` with norm `‖·‖` and matrices `A, B ∈ 𝔤` with `‖A‖, ‖B‖ ≤ δ`, the BCH order-2 remainder satisfies*
> 
> *  `‖exp(A) · exp(B) · exp(−A) · exp(−B) − exp([A, B])‖ ≤ K_BCH · (‖A‖³ + ‖B‖³)`
> 
> *for an explicit constant `K_BCH`.*

**Current state**: shipped SU(2)-specific in `lean/SKEFTHawking/FKLW/SU2BCHBracketClosure.lean` (the `fourfoldComm_norm_le` chain). The proof is generic at the technique level — it's just `exp`-power-series manipulation + commutator algebra. The SU(2) specialization is mostly type-restriction; the generalization to any matrix Lie algebra over ℂ should be a syntactic refactor (replace `Matrix (Fin 2) (Fin 2) ℂ` with `Matrix (Fin n) (Fin n) ℂ` or even `Matrix m m ℂ`).

**Work estimate**: ~200-400 LoC to extract, generalize, de-privatize, and add Mathlib-style docstrings + examples.

### M.2 — Generic density-from-Cartan-v4-witness lemma

**Statement (to ship in Mathlib upstream form)**:

> *Any closed subgroup `H` of a compact connected matrix Lie group `G` containing two ℝ-linearly-independent 1-parameter subgroups equals the whole group: `H = G`.*

**Current state**: shipped SU(2)-specific in `lean/SKEFTHawking/FKLW/CartanSubstrate.lean` (`CartanFinalStep_SU2_v4_holds`). The mathematical content is Cartan's closed-subgroup theorem specialized to compact connected groups; the SU(2) version uses BCH bracket closure (Phase 5 Step 13 substrate) + the 3-dim SU(2)-specific argument.

**Generalization path**: the technique extends to any compact connected matrix Lie group. For SU(d), the analog uses the same BCH chain + a d-dependent Cartan dimension count. For arbitrary compact connected matrix Lie group, the substrate is heavier (general Lie-algebra dimension count). Mathlib4 v4.29.1 has `Mathlib/Topology/Algebra/Group/Basic.lean` with `Subgroup.topologicalClosure` and related, but the substantive Cartan-theorem content is absent.

**Work estimate**: ~300-600 LoC to extract and ship at the SU(d) level. Full compact-connected-matrix-Lie-group version is a much larger lift (~1,000-2,000 LoC; deferred).

### M.3 — Three-direction-product strict differentiability

**Statement (already shipped)**:

> *For Banach spaces `E_1, E_2, E_3` and `F`, and a function `f : E_1 × E_2 × E_3 → F` that is `C¹` in each variable separately at zero with directional derivatives `D_1 f, D_2 f, D_3 f : F`, the three-direction product map satisfies `HasStrictFDerivAt` at zero with derivative `λ (x_1, x_2, x_3) → D_1 f · x_1 + D_2 f · x_2 + D_3 f · x_3`.*

**Current state**: shipped as `private lemma threeDirProduct_hasStrictFDerivAt_zero` in `SU2BCHBracketClosure.lean:910`. Used at line 1239 of the same file. The technique is generic — the SU(2)-specific context only enters through the input space's matrix typing.

**Work assessment**: per the Phase 6u Strategic Positioning user-note, this one "may already be complete" — i.e., the technique is generic, the only Mathlib-upstream work is de-privatizing + generalizing the typed (matrix Lie group) input space to a Banach-space input space. If Mathlib4 already has the general `HasStrictFDerivAt` 3-direction product (let me check), the SU(2) usage is a specialization and no upstream work is needed. If Mathlib4 doesn't have it, the extraction is ~100-200 LoC.

**Sub-wave M.3.0**: investigate Mathlib4 v4.29.1 coverage. Search for `HasStrictFDerivAt.prod` chains, `ContinuousLinearMap` 3-direction product lemmas. If existing coverage suffices, M.3 is **NO-OP** — the SU(2)-specific use is correct, just a private specialization of an upstream API. If not, ship the extraction (~100-200 LoC).

### Aggregate Track M effort

~600-1,200 LoC across M.1 + M.2 + M.3 (with M.3 plausibly NO-OP after investigation). Each PR is independently shippable.

### Audience

Mathlib4 working groups on Lie theory / matrix exponentials / topological groups; the broader formal-methods quantum-computing community (these lemmas enable other groups to do similar verified-quantum-compiler work without re-deriving SU(d) substrate).

### Risk

LOW. The lemmas are well-understood mathematically; the work is extract + generalize + upstream-format. The main risk is Mathlib stylistic-review iteration cost (typical for Mathlib PRs).

---

## Cross-cutting work

### Constructive ε₀-net follow-on (deferred from Phase 6u Wave 3)

Phase 6u Wave 3 shipped the **existential** form (Classical.choose extraction from density). The **constructive** finite-Finset coverage form (originally documented but deferred per `GenericEpsilonNet.lean` Status note) is per-alphabet:

  - For Clifford+T: Ross-Selinger 2014 symbolic ℤ[ω][1/√2] discharge gives a constructive ε₀-net via the algebraic-number-theoretic structure of Clifford+T words.
  - For Fibonacci: existing `FibonacciEpsilonNet.lean` is also existential; constructive Path-A enumeration per Phase 6t Wave 3 user lock-in §13.2.

Phase 6x can pick up the constructive ε₀-net for Clifford+T as a substantive ship (~250-500 LoC) — moves the Track T-S compiler from `Classical.choose`-noncomputable to genuinely-runnable. Not blocking; deferred to per-alphabet engineering preference.

### Length-bound concrete-word coupling (CP2 RC2 from Phase 6u)

CP2 RC2 flagged that the length-bound conjunct in the Wave 6 / Track-T-S.5 headline references `skLength` (abstract recursion-depth length), not the concrete compiled `FreeGroup` word length. The tightened version — `(compile U ε).toWord.length ≤ skLength (skLevel_polylog ε)` chained with the existing bound — is **Mathlib-PR-quality follow-up** that affects all generating-set instances. Could be picked up in Phase 6x as Track M.4 if desired; flagged here for explicit visibility.

### Adversarial-review checkpoints

Per `BUNDLE_LIFT_PROCEDURE.md` Stage 13 hard gate, each Phase 6x track gets its own checkpoint:

  - **CP-B** — after Track T-B (Read-Rezayi instances).
  - **CP-A1** — after Track T-A1 (trapped-ion).
  - **CP-A2** — after Track T-A2 (Clifford+CCZ + SU(d) extension).
  - **CP-M** — after each Mathlib upstream PR is accepted (or after the project-side Lean ship if Mathlib review takes a while).

### Pipeline Invariants

- **#10 (no `maxHeartbeats`)**: RESPECTED throughout. The Phase 6u Wave 4b discharge pattern (extract `valid_branch_K_chain_le_K_compose_numeric` helper to top level rather than override the heartbeat budget) applies to Phase 6x — if any track's main theorem hits the heartbeat budget, decompose via top-level numerical helpers.
- **#15 (no new axioms without user sign-off)**: RESPECTED. Pivot rule explicit: if any track's closure-density witness requires substrate beyond Mathlib4 v4.29.1, YIELD for user sign-off.

---

## Cross-references

- **Phase 6u roadmap** (`docs/roadmaps/Phase6u_Roadmap.md`) — generic-substrate predecessor; the W1-W6 substrate that Phase 6x track instantiations inherit.
- **Phase 6u Implications** (`docs/stakeholder/Phase6u_Implications.md`) — accessible technical overview of what the Phase 6u substrate ships; useful for stakeholder positioning of Phase 6x tracks.
- **Phase 6u Strategic Positioning** (`docs/stakeholder/Phase6u_Strategic_Positioning.md`) — audience targeting + Mathlib upstream rationale (the basis for Phase 6x Track M).
- **Phase 6t roadmap** (`docs/roadmaps/Phase6t_Roadmap.md`) — Fibonacci-specific predecessor providing the "canonical first alphabet instance" template that Phase 6u generalized and Phase 6x replicates per alphabet.
- **Phase 6u Generic substrate**: `lean/SKEFTHawking/FKLW/Generic*.lean` (7 files) — the alphabet-agnostic chain that every Phase 6x track instantiation consumes.
- **Phase 6u Clifford+T instance**: `lean/SKEFTHawking/FKLW/CliffordT*.lean` (8 files) — the canonical 5-sub-wave template per Phase 6x track.
- **Bundle Readiness Heatmap** (`docs/BUNDLE_READINESS_HEATMAP.md`) — for tracking D4 §9.8 absorption status as Phase 6x tracks ship.
- **Phase 6u Roadmap** (`docs/roadmaps/Phase6u_Roadmap.md`) "Track T-A1/T-A2/T-B" rows — original re-slot decision documenting why these tracks did not fit Phase 6v / 6w scope (Phase 6v + 6w committed to other strategic content per the 2026-05-25 scope finalization).

---

## 2026-05-27 Audit Addendum — Orphan Work for Full Phase 6x Spec Closure

**Trigger.** Post-Phase-6x-completion audit (2026-05-27, autonomous-loop agent) identified six items deferred by the Phase 6x completion ship that the Phase 6y roadmap does NOT pick up. Three are residuals from the PM-completion retrospective-addendum 5-failure-mode close (concrete-length conjuncts remained conditional for three of four FreeGroup alphabets despite the addendum's "all four" framing); three are deferred Mathlib follow-ons of varying urgency.

**Independent deep research.** A Ross-Selinger Pre-Implementation Research Dossier (`Lit-Search/Phase-6x/Ross-Selinger Clifford+T Synthesis- A Pre-Implementation Research Dossier.md`, 2026-05-27) provides milestone decomposition and quantitative bounds for the largest deferred item (orphan #2). Key sequencing insight: **M4 (KMM exact synthesis) alone discharges the algorithmic core of `baseFinder` correctness; M3 (grid-problem solver) supplies the candidate `(u, t)` and can land later.** The deterministic Selinger-2012 branch (T-count `K + 4·log₂(1/ε)`, K ≈ 11) suffices for the `skLengthBaseCase = 100` budget when SK base-case precision `ε₀ = 2⁻⁴`, yielding worst-case word length L ≤ 90 with 10-gate margin. The factoring-oracle / number-theoretic-hypothesis branch is explicitly deferred.

### The six orphans

| # | Orphan | Phase 6y status | Verdict |
|---|---|---|---|
| 1 | M.1 m-generic upgrade (`Matrix m m ℂ` from Fin-d) | Not in Track M-S scope; predecessor-assumption only consumes Fin-d form | **Homeless** |
| 2 | Ross-Selinger optimal ℤ[ω][1/√2] algorithmic synthesis | Lit-Search task drop only | **Homeless (DR-scoped)** |
| 3 | Unconditional 3-conjunct concrete-length headlines for RR5/RR7 | Not in 6y scope | **Homeless (high-leverage)** |
| 4 | T-A1 lift/shift unconditional headline upgrade to 3-conjunct | Implicit residual of retrospective failure mode #4 | **Homeless** |
| 5 | Fibonacci constructive ε₀-net (Path-A per Phase 6t §13.2) | Not in 6y scope | **Homeless** |
| 6 | SU(2) compactness as Mathlib-PR-quality lemma | Not in 6y Track M-S scope (M-S.1 Cartan + M-S.2 exp local homeo only) | **Homeless** |

Items #3, #4 close the retrospective addendum's claim of failure-mode-#4 ("substrate vs headline") closure. Items #4 and #6 are tiny. Item #2 has DR-validated sequencing. Items #1, #5 are quality-of-life follow-ons.

### Phase 6y coordination — DO NOT TOUCH list

A parallel autonomous agent is actively executing Phase 6y (HEAD `66b227d` at addendum time; mid-loop on Track S.2g substrate, untracked `GenericSUdCartanUnconditional.lean` in flight per the 2026-05-27 Explore-agent audit). Phase 6y-owned file space — **DO NOT TOUCH** during any Tier 1 / Tier 2 ship:

- `lean/SKEFTHawking/FKLW/GenericSUd*.lean` — Track S substrate (all files; agent active)
- `lean/SKEFTHawking/FKLW/TrappedIonGeneratingSetSU4*.lean` + `TrappedIonSU4*.lean` — Track T-A1′
- `lean/SKEFTHawking/FKLW/CliffordCCZGeneratingSetSU8*.lean` + `CliffordCCZSU8*.lean` — Track T-A2′
- `lean/SKEFTHawking/CartanFinalStepSUdGenericMathlibPR.lean` — Track M-S.1 (shipped at commit `35a7716`)
- `lean/SKEFTHawking/MatrixExpLocalHomeomorphMathlibPR.lean` — Track M-S.2 (shipped at `c7a4be5`)
- `lean/SKEFTHawking/MatrixBCHCubicMathlibPR.lean` — **read-only** (Phase 6y consumes Fin-d form; Item J in this addendum modifies it but only after gate)

Every orphan-ship goal below carves around this list. Orphan ships add new files or modify only files outside this list (sole exception: Item C's small update to `RossSelingerLightweight.lean` to use the new compactness instance, which Phase 6y doesn't touch).

---

### Tier 1 — Quick wins (single-session, fully isolated)

Closes retrospective failure modes #4 and #5 + adds one new Mathlib-PR-quality file. Total ~500-700 LoC across four single-session items, all parallel-safe with active Phase 6y agent.

#### Item A — T-A1 lift/shift unconditional 3-conjunct headline

**GOAL:** Ship `solovayKitaev_dawson_nielsen_quantitative_trappedIon_strict_concrete_constructive_unconditional` — a 3-conjunct UNCONDITIONAL bundled-strict headline for T-A1 lift/shift, adding the concrete-word-length conjunct.

**BOOTSTRAP:** read `CLAUDE.md` (workspace + project), this addendum, then:
- `lean/SKEFTHawking/FKLW/TrappedIonGeneratingSet.lean` — current 2-conjunct headline + `perIonInject`
- `lean/SKEFTHawking/FKLW/RossSelingerLightweight.lean` — `cliffordTBaseFinder_constructive` (UNCONDITIONAL) + length bound
- `lean/SKEFTHawking/FKLW/PerAlphabetConcreteLengthHeadlines.lean` — current conditional `_strict_concrete` for T-A1

**KEY INSIGHT:** T-A1 density factors through CT (`ρ_TI.comp (FreeGroup.map perIonInject) = ρ_CliffT`). The CT constructive base finder lifts directly via `FreeGroup.map perIonInject`, which preserves word length.

**DELIVERABLES:**
1. `trappedIonBaseFinder_constructive := FreeGroup.map perIonInject ∘ cliffordTBaseFinder_constructive` (in `TrappedIonGeneratingSet.lean` or new sibling `FKLW/TrappedIonBaseFinder.lean`).
2. `trappedIonBaseFinder_constructive_approximates_within_two_ε₀` via the factorization equality.
3. `trappedIonBaseFinder_constructive_length_bounded` via `FreeGroup.map` length preservation.
4. The 3-conjunct UNCONDITIONAL headline.

**ACs:**
- Theorem UNCONDITIONAL; `#print axioms` = `{propext, Classical.choice, Quot.sound}`.
- `cd lean && lake build` clean.
- `uv run python scripts/validate.py` passes; `counts.json::lean.axioms` still 0.
- Retrospective failure mode #4 closed for T-A1.

**DO NOT TOUCH:** see Phase 6y coordination list above.

**EXIT:** commit `feat(phase6x-residual-A): T-A1 3-conjunct unconditional via CT base finder composition`.

#### Item B-RR5 — Read-Rezayi SU(2)_5 lightweight constructive base finder

**GOAL:** Ship `solovayKitaev_dawson_nielsen_quantitative_readRezayiK5_strict_concrete_constructive_unconditional` — 3-conjunct UNCONDITIONAL bundled-strict headline for Read-Rezayi SU(2)_5, mirroring the Clifford+T T-S′ pattern.

**BOOTSTRAP:** `CLAUDE.md`, this addendum, then:
- `lean/SKEFTHawking/FKLW/RossSelingerLightweight.lean` — canonical T-S′ pattern: ConstructiveEpsilonNet + density witness + Finset enumeration → UNCONDITIONAL constructive base finder. Mirror this exactly.
- `lean/SKEFTHawking/FKLW/ReadRezayiK5ClosureDenseWitness.lean` — unconditional RR5 density (`rr5_density_unconditional`), via Chebyshev T_7 / `−1/4 ∈ ℤ̄`.
- `lean/SKEFTHawking/FKLW/ReadRezayiK5Quantitative.lean` — current 2-conjunct unconditional headline.
- `lean/SKEFTHawking/FKLW/GenericEpsilonNet.lean` — `finite_epsilon_net_of_compact_dense`.
- `lean/SKEFTHawking/FKLW/PerAlphabetConcreteLengthHeadlines.lean` — existing conditional `_strict_concrete` for RR5.

**DELIVERABLES (new file `lean/SKEFTHawking/FKLW/ReadRezayiK5BaseFinder.lean`):**
1. `rr5FiniteCover` — finite Finset of ε₀-covering RR5 FreeGroup words via `finite_epsilon_net_of_compact_dense` + RR5 density + SU(2) compactness.
2. `rr5BaseFinder_constructive` — `Finset.choose`-based UNCONDITIONAL constructive base finder.
3. `rr5BaseFinder_constructive_approximates_within_two_ε₀` (UNCONDITIONAL).
4. `rr5BaseFinder_constructive_length_bounded` (UNCONDITIONAL).
5. Ship the 3-conjunct UNCONDITIONAL headline by composition with the generic strict bundled headline.

**ACs:**
- All four theorems UNCONDITIONAL; `#print axioms` = standard kernel.
- `lake build` clean; `validate.py` passes; `counts.json::lean.axioms` still 0.
- Retrospective failure mode #4 closed for RR5.

**DO NOT TOUCH:** see Phase 6y coordination list.

**EXIT:** commit `feat(phase6x-residual-B-RR5): RR5 constructive base finder + 3-conjunct unconditional headline`.

#### Item B-RR7 — Read-Rezayi SU(2)_7 lightweight constructive base finder

**GOAL:** Ship `solovayKitaev_dawson_nielsen_quantitative_readRezayiK7_strict_concrete_constructive_unconditional` — 3-conjunct UNCONDITIONAL bundled-strict headline for Read-Rezayi SU(2)_7.

**BOOTSTRAP:** `CLAUDE.md`, this addendum, then:
- `lean/SKEFTHawking/FKLW/RossSelingerLightweight.lean` — T-S′ pattern to mirror.
- `lean/SKEFTHawking/FKLW/ReadRezayiK7ClosureDenseWitness.lean` — unconditional RR7 density (`rr7_density_unconditional`), via triple-angle `4cos³(π/9) − 3cos(π/9) = 1/2` / `1/2 ∈ ℤ̄`.
- `lean/SKEFTHawking/FKLW/ReadRezayiK7Quantitative.lean` — current 2-conjunct unconditional headline.
- `lean/SKEFTHawking/FKLW/GenericEpsilonNet.lean` — `finite_epsilon_net_of_compact_dense`.
- `lean/SKEFTHawking/FKLW/PerAlphabetConcreteLengthHeadlines.lean` — current conditional `_strict_concrete` for RR7.

**REUSE:** Identical structure to B-RR5. If B-RR5 lands first, this is bulk-substitution; consider parameterizing a shared `…RRkBaseFinder` helper if mechanically obvious.

**DELIVERABLES (new file `lean/SKEFTHawking/FKLW/ReadRezayiK7BaseFinder.lean`):**
1. `rr7FiniteCover`.
2. `rr7BaseFinder_constructive` UNCONDITIONAL.
3. `rr7BaseFinder_constructive_approximates_within_two_ε₀` UNCONDITIONAL.
4. `rr7BaseFinder_constructive_length_bounded` UNCONDITIONAL.
5. The 3-conjunct UNCONDITIONAL headline.

**ACs:**
- All UNCONDITIONAL; kernel-only.
- `lake build` clean; `validate.py` passes; `counts.json::lean.axioms` = 0.
- Retrospective failure mode #4 closed for RR7.

**DO NOT TOUCH:** see Phase 6y coordination list.

**EXIT:** commit `feat(phase6x-residual-B-RR7): RR7 constructive base finder + 3-conjunct unconditional headline`.

#### Item C — SU(2) compactness Mathlib-PR-quality lemma

**GOAL:** Ship `Matrix.specialUnitaryGroup_compactSpace` as a Mathlib-PR-quality `[CompactSpace (specialUnitaryGroup (Fin n) ℂ)]` instance, removing the explicit `Matrix.specialUnitaryGroup_isCompact` hypothesis from the project's T-S′ chain.

**BOOTSTRAP:** `CLAUDE.md`, this addendum, then:
- `lean/SKEFTHawking/FKLW/RossSelingerLightweight.lean` — current consumer of the explicit hypothesis
- `lean/SKEFTHawking/FKLW/GenericEpsilonNet.lean` — uses `IsCompact`
- `Mathlib.LinearAlgebra.UnitaryGroup` — Mathlib's `unitaryGroup` compactness; `specialUnitaryGroup` is the missing parallel

**KEY INSIGHT:** `specialUnitaryGroup (Fin n) ℂ` is a closed subgroup of `unitaryGroup (Fin n) ℂ` via the continuous `det = 1` constraint. Closed-subspace-of-compact pattern. ~30-80 LoC.

**DELIVERABLES (new file `lean/SKEFTHawking/SU2CompactnessMathlibPR.lean`):**
1. `Matrix.specialUnitaryGroup_isClosed` — det-1 subset is closed.
2. `Matrix.specialUnitaryGroup_compactSpace` instance + `_isCompact` lemma.
3. Mathlib-PR-quality presentation: `Matrix` namespace, docstring with rationale, worked SU(2) and SU(3) examples.
4. Update `RossSelingerLightweight.lean` to use the new instance instead of the explicit compactness hypothesis.

**ACs:**
- Instance is generic over `n` (Fin n with `[Fintype n] [DecidableEq n]` adequate).
- `RossSelingerLightweight.lean` no longer requires explicit `IsCompact` hypothesis on the T-S′ chain.
- `lake build` clean; `validate.py` passes.
- File is upstream-ready (namespace, docstring, examples).

**DO NOT TOUCH:** see Phase 6y coordination list.

**EXIT:** commit `feat(phase6x-residual-C): Matrix.specialUnitaryGroup compactness + T-S′ hypothesis removal`.

---

### Tier 2 — Ross-Selinger arc (multi-session, new directory `lean/SKEFTHawking/FKLW/RossSelinger/`)

DR-validated 5-milestone decomposition. Total ~2,500 LoC across the deterministic-branch arc (omits factoring branch per DR §R6). Parallel-safe with Phase 6y because all work lives in a new subfolder.

**Sequencing** per DR §R5 + the project's incremental-headline preference:
1. D (M1, ZOmega) — foundation.
2. E (M2, ZOmegaSqrt2) — consumes D.
3. F (M4, KMM) — consumes D + E.
4. G (M5 stub, KMM base finder at ε₀=2⁻⁴) — consumes F; **closes orphan #2 at deterministic-branch level even without M3**.
5. H (M3, grid synthesis) — quality-of-implementation upgrade after G.
6. I (M5 full + pygridsynth cross-validation) — final composition.

#### Item D (M1) — `ZOmega` ring of integers of ℚ(ζ₈)

**GOAL:** Ship `ZOmega` — the ring of integers of ℚ(ζ₈), as a Lean 4 `structure` with four `ℤ` fields, computable arithmetic, `DecidableEq`, and a `RingHom` to `ℂ`. M1 of the Ross-Selinger arc per DR §1.

**BOOTSTRAP:** `CLAUDE.md`, this addendum, then:
- `Lit-Search/Phase-6x/Ross-Selinger Clifford+T Synthesis- A Pre-Implementation Research Dossier.md` — §1.1 (multiplication table) + §1.4 (gaps table)
- `Mathlib.NumberTheory.Zsqrtd.Basic` — canonical API shape (`re`/`im`, `Zsqrtd.lift`)
- `Mathlib.NumberTheory.Zsqrtd.GaussianInt` — embedding-to-ℂ pattern
- `Mathlib.RingTheory.Polynomial.Cyclotomic.Basic` — source of `Φ₈ = X⁴ + 1`

**KEY CONSTRAINT (DR §1.1, HIGH confidence):** Do NOT instantiate `CyclotomicRing 8 ℤ ℚ(ζ₈)` — non-computable, blocks `native_decide`. Use a 4-tuple structure mirroring Selinger's Haskell `Omega Integer`.

**DELIVERABLES (new dir `lean/SKEFTHawking/FKLW/RossSelinger/`, new file `ZOmega.lean`):**
1. `structure ZOmega where a b c d : ℤ deriving DecidableEq, Repr` (a=ω³ coef, b=ω², c=ω, d=constant).
2. `instance : CommRing ZOmega` with multiplication table from DR §1.1 (ω⁴ = −1).
3. `ZOmega.norm : ZOmega → ℤ` (algebraic norm via Galois conjugates).
4. `ZOmega.conj : ZOmega → ZOmega` (complex conjugation = ω → −ω³).
5. `noncomputable def ZOmega.toComplex : ZOmega →+* ℂ` + injectivity via `Φ₈` irreducibility.
6. `ZOmega.lift : { r : R // r^4 = -1 } ≃ (ZOmega →+* R)` — universal property mirroring `Zsqrtd.lift`.

**ACs:**
- Arithmetic computable; `native_decide` reduces `(⟨1,0,0,0⟩ * ⟨0,1,0,0⟩ : ZOmega)` to canonical form.
- `lake build` clean; ~400 LoC (DR §1.4); `counts.json::lean.axioms` = 0.
- File is Mathlib-upstream-ready (candidate namespace `Mathlib.NumberTheory.Cyclotomic.ZOmega`; docstrings; worked examples).

**DO NOT TOUCH:** see Phase 6y coordination list.

**EXIT:** commit `feat(phase6x-residual-D-M1): ZOmega ring of integers of ℚ(ζ₈) as computable 4-tuple`.

#### Item E (M2) — `ZOmegaSqrt2 := ℤ[ω][1/√2]` dual representation

**GOAL:** Ship `ZOmegaSqrt2 := ℤ[ω][1/√2]` per DR §1.7 with a dual representation: runtime 4-tuple-plus-exponent (for `native_decide`) plus theory-layer `Localization.Away (√2 : ZOmega)` with an equivalence proof. M2 of the Ross-Selinger arc.

**BOOTSTRAP:** `CLAUDE.md`, this addendum, then:
- DR §1.7 (dual-representation design) + §1.2 (Mathlib survey)
- D output (`RossSelinger/ZOmega.lean`) — prerequisite
- `Mathlib.RingTheory.Localization.Away.Basic` and `Mathlib.RingTheory.Localization.Basic` — `Localization.Away`, `IsLocalization.lift`
- `Mathlib.RingTheory.Localization.Defs` — universal property

**KEY MATHEMATICAL FACT:** `√2 = ω + ω⁻¹ = ω − ω³ = (⟨−1, 0, 1, 0⟩ : ZOmega)`. So √2 is already in `ZOmega`; we localize at this element.

**DELIVERABLES (new file `lean/SKEFTHawking/FKLW/RossSelinger/ZOmegaSqrt2.lean`):**
1. `structure ZOmegaSqrt2Runtime where z : ZOmega; k : ℕ` representing `z / (√2)^k`, with equivalence `(z, k) ∼ (√2·z, k+1)`.
2. `instance : CommRing ZOmegaSqrt2Runtime` via quotient.
3. `def ZOmegaSqrt2 : Type := Localization.Away (sqrt2 : ZOmega)` — theory rep.
4. `equivRuntimeLocalization : ZOmegaSqrt2Runtime ≃+* ZOmegaSqrt2` — bridge equivalence.
5. `DecidableEq ZOmegaSqrt2Runtime` via canonical-form normalization.
6. `noncomputable def ZOmegaSqrt2.toComplex : ZOmegaSqrt2 →+* ℂ` via universal property.
7. Worked examples + Mathlib-PR-quality docstrings.

**ACs:**
- Runtime ops `native_decide`-able; theory ops Mathlib-conventional.
- Equivalence proof: `equivRuntimeLocalization` is a ring isomorphism.
- `lake build` clean; ~600 LoC (DR §1.4); kernel-only; axioms unchanged.

**DO NOT TOUCH:** Phase 6y coordination list. Do NOT modify D outputs except via import.

**EXIT:** commit `feat(phase6x-residual-E-M2): ZOmegaSqrt2 dual runtime+theory representation`.

#### Item F (M4) — KMM exact synthesis

**GOAL:** Ship `kmmReduce : Matrix (Fin 2) (Fin 2) ZOmegaSqrt2 → List CliffordTGate` with sde-decreasing termination, correctness `interp (kmmReduce U) = U`, and length bound `n_g ≤ N₃ + 4·sde(U)`. M4 per DR §3.3 + Selinger 2012 deterministic.

**BOOTSTRAP:** `CLAUDE.md`, this addendum, then:
- DR §3 + §4
- arXiv:1206.5236 (KMM 2013) — Algorithm 1, Theorem 1, Corollary 1
- arXiv:1312.6584 (Giles-Selinger 2013) — Theorem 7.10 (MA T-count = sde)
- D + E outputs (`RossSelinger/ZOmega.lean`, `ZOmegaSqrt2.lean`)
- `lean/SKEFTHawking/FKLW/CliffordTGeneratingSet.lean` — project `CliffordTGate` reference

**ALGORITHM (DR §3.3):** For `U` of sde ≥ 4, ∃ `j ∈ {0,1,2,3}` with `(HT^j)·U` sde-reduced by 1. Iterate until sde ≤ 3, then lookup-table the ≤192 single-qubit Cliffords. `chooseReduction` computes the `ZOmega/√2·ZOmega` residue (KMM Lemma 3).

**DELIVERABLES (new `RossSelinger/CliffordTGate.lean`, `RossSelinger/KMM.lean`):**
1. `CliffordTGate` ADT + `gateMatrix : CliffordTGate → Matrix (Fin 2) (Fin 2) ZOmegaSqrt2`.
2. `sde : Matrix (Fin 2) (Fin 2) ZOmegaSqrt2 → ℕ` (least denominator exponent).
3. `chooseReduction : … → Fin 4` (KMM Lemma 3).
4. `cliffordLookup` for sde ≤ 3.
5. `kmmReduce` with `termination_by sde U`.
6. `kmmReduce_correct`, `kmmReduce_length_bound`.

**ACs:**
- All computable; `native_decide` reduces small examples.
- `lake build` clean; ~800 LoC; axioms = 0.
- `N₃` pinned with `#eval` evidence in docstring.
- Length bound uses Giles-Selinger MA Theorem 7.10.
- M4 alone is sufficient to define a real constructive Clifford+T base finder when paired with G (does not block on M3).

**DO NOT TOUCH:** Phase 6y coordination list.

**EXIT:** commit `feat(phase6x-residual-F-M4): KMM exact synthesis with sde-decreasing termination + length bound`.

##### Finish-F PROGRESS LEDGER + source-grounded build plan (2026-05-29 session)

**Substrate SHIPPED (19 kernel-pure commits, runtime ring `ZOmegaSqrt2`):**
`ZOmegaSqrt2` runtime `CommRing` (Quotient of `Frac`) + computable `CliffordTGate`
`gateMatrix`/`interp` + `Sde.lean` (`dividesSqrt2`/`divSqrt2`/`lowestDenExp` +
`denExp` quotient lift + `denExp_le_iff` clearing char) + `SdeMatrix.lean`
(`sdeC`) + `KMMReduce.lean` (`T⁸=I`, `reconWord`, `interp_reconWord_mul`) +
`Conj.lean` (`conj`/`normSq` algebra) + `ResidueSqrt2.lean` (the
`𝔽₂[ε]/(ε²)` residue ring, NOT 𝔽₄ — √2=𝔭² not prime) + `GdeSqrt2.lean`
(`dvdSqrt2Pow` decidable predicate) + `UnitaryT.lean` (`IsUnitaryT` + column
normSq) + `DenExpValuation.lean` (non-archimedean `denExp` + **Lemma 4 core**
`denExp_normSq_col0_eq`) + `RealSubring.lean` (ℤ[√2] peel swap `(a,b)↦(b,a/2)`,
Prop 1 substrate) + `GdeValue.lean` (**ℕ-valued `gdePeel` + predicate↔value
bridge `dvdSqrt2Pow_iff_le_gdePeel`**).

**SOURCE-GROUNDED Lemma statements (verbatim from arXiv:1206.5236, this session):**
- **Lemma 3:** for `(z w)ᵀ` over `ℤ[1/√2,i]` with `sde(|z|²) ≥ 4`, for each
  `s∈{−1,0,1}` ∃ `k∈{0,1,2,3}` with `sde(|z+wωᵏ/√2|²) − sde(|z|²) = s`.
  (Synthesis uses `s=−1`.) Proof = `gde(|x+ωᵏy|²) − gde(|x|²)` achieves all of
  `{1,2,3}`, case split `gde(|x|²)∈{0,1}`.
- **Lemma 4:** `|z|²+|w|²=1`, `sde(z)≥1 ∨ sde(w)≥1` ⟹ `sde(z)=sde(w)` and
  `gde(|x|²)=gde(|y|²)≤1` (`x=z√2^sde(z)`, `y=w√2^sde(w)`).
- **Lemma 5:** `|x|²+|y|²=√2^m` ⟹ `gde(|x+y|²) ≥ min(m, 1+⌊(gde|x|²+gde|y|²)/2⌋)`.
- **Prop 1:** `gde(a+√2b)` even ⟺ `v₂(b) ≥ v₂(a)` (matches `RealSubring` peel).
- **Algorithm 1:** tracks `s = sde(|z₀₀|²)`; loop while `s>3`; base case `s≤3`
  (table 𝕊₃ of all `sde≤3` unitaries); each step emits syllable `TᵏH`, `k≤3`.

**KEY CORRECTION — the algorithm tracks `sde(|z₀₀|²)` (squared modulus), base
case `sde(|z₀₀|²) ≤ 3`** (not `sde(M) ≤ 3` of the raw matrix). The `chooseReduction`
/ `kmmReduce` specs in `KMM.lean` currently phrase reduction over `sde M`; the
concrete instance must phrase it over `sde(|z₀₀|²)` per the source.

**⚠ SCAFFOLD DEFECT (must fix at assembly):** `KMMReduce.reconWord j :=
replicate (8−j) .T ++ [.H]` uses up to **8 raw T gates/step**, achieving only
`N₃ + 9·k`. Algorithm 1 emits `TᵏH` (k≤3, ≤4 gates/step) → the `N₃ + 4·k`
bound the `KMMReduction.length_bound` field hardcodes. **Fix:** emit the
reconstruction syllable `T^(8−k)·H` S/Z-compressed (`T⁷=Z·S·T`, `T⁶=Z·S`,
`T⁵=Z·T`; S,Z ∈ CliffordTGate) → ≤4 gates/step. The `interp_reconWord_mul`
correctness identity stays valid (same operator, fewer gates). Without this the
honest bound is `N₃+9·k`, which would force re-stating Item G's `L≤90<100`
arithmetic.

**DISCHARGE NOTE:** `Nonempty KMMReduction` CANNOT be discharged by
`Classical.choose` of `IsCliffordTRealizable` — that gives `correct` for free
but provides NO `length_bound` (a random gate sequence). The `length_bound`
field IS KMM Corollary 1, so the discharge requires the actual algorithm +
length analysis. No shortcut.

**DOSSIER READ DIRECTLY (2026-05-29, per CLAUDE.md no-delegation rule)** —
`Lit-Search/Phase-6x/Ross-Selinger Clifford+T Synthesis- A Pre-Implementation
Research Dossier.md`. Canonical reference. Confirms: (i) bound
`n_g(U) ≤ N₃ + 4·sde_{|·|²}(U)` (Cor 1, p.7–8) + reverse
`sde ≤ N_{H,3}+3+⌊(n_g−N₃)/2⌋`; (ii) §3.3 `chooseReduction` = residue of `U`'s
entries in `ZOmega/√2 ≃ ZMod 2[i]` (= our `ResidueSqrt2` ring `𝔽₂[ε]/(ε²)`,
since `𝔽₂[i]=𝔽₂[x]/((x+1)²)`) selecting the unique `j`; (iii) `kmmReduce` uses
a FUEL `n` (init = sde), base `cliffordLookup U` at `n=0`; (iv) `N₃` value is
UNKNOWN to the dossier — compute by `#eval`/BFS over the `sde≤3` orbit and pin
as a `def`. NB the dossier's `kmmReduce` sketch emits `T^j::H::gates`, which is
LOOSE — the rigorous reconstruction is `T^(8−j)·H` (our `interp_reconWord_mul`).

**REMAINING build order (each MCP-verified, kernel-pure):**
1. ✅ `gdePeel` ℕ-valued gde + predicate↔value bridge — SHIPPED (`b5771b9`).
   ✅ `NormSqGde.lean` — `normSq`/`gdeNormSq` foundation — SHIPPED (`f36f5a0`).
   ✅ **Prop 1 (mod-8 form) SHIPPED** (`PropOneBridge.lean`, `29345fb`) —
   `coord4_gde_coordOf : KMM.Coord4.gde (coordOf x) = gdePeel (normSq x) 4` (the
   gde-value bridge). The valuation closed form was NOT needed: instead
   `gdePeel (normSq x) 4 = peelN (normSq x).d (normSq x).c 4` (real-subring peel,
   `PropOne.lean`), `peelN _ _ 4` is periodic mod 8 (reads A,B mod 4), and on the
   64 integer representatives `peelN a b 4 = gdeFromPQ (a,b mod 8)` by kernel
   `decide`. `Pform/Qform_coordOf` identify the residues. Kernel-pure (no
   native_decide). Oracle-validated 0-mismatch (gdeMod8 == peel-gde).
2. ✅ **Lemma 4** core SHIPPED (`denExp_normSq_col0_eq`); `gde(|x|²)∈{0,1}`
   oracle-confirmed. (Value-form lift folds into Lemma 3's case analysis.)
3. ✅ **Lemma 5** SHIPPED (`CrossTermGde.lean`, `dbe079b`) — `dvdSqrt2Pow_normSq_add`:
   `√2^g₁∣|x|², √2^g₂∣|y|², |x|²+|y|²=√2^M ⟹ √2^(min M ((g₁+g₂)/2+1))∣|x+y|²`.
   VALUATION-FREE route (no Prop 1 v₂ closed form): the "+1" came from
   `dvdSqrt2Pow_add_conj` (`√2∣(w+conj w)` always ⟹ `√2^m∣u ⟹ √2^(m+1)∣(u+conj u)`)
   + the halving `dvdSqrt2Pow_normSq_half` (`√2^(2m)∣|u|²⟹√2^m∣u`, base case a
   ZMod-2 `decide`) + `|u|²=|x|²|y|²` + the `GdeArith` non-archimedean toolkit.
   All pieces oracle-validated (0 violations).
3b. **DEEP RESEARCH DISPATCHED (2026-05-29)** —
   `Lit-Search/Tasks/submitted/20260529_phase6x_kmm_lemma3_proof_mechanisms.md`.
   Targets the proof-mechanism gaps (NOT Mathlib, NOT statements — which we have):
   Q1 KMM Lemma 3 COMPLETE proof + `chooseReduction` selection rule + the `𝔭`-adic
   `∃k: v_𝔭(x'+ωᵏy')=3` argument; Q2 the 𝕊₃ base case + the numeral `N₃`
   (dossier flags it UNKNOWN); Q3 Ross-Selinger §5/§6 deterministic proofs for
   Items H/I. Rationale: reconstructing Lemma 3 solo is the highest-risk step
   (4 would-be errors already caught by the oracle); per the quality standard,
   fill the proof gap via the primary source rather than risk a flawed
   reconstruction. Meanwhile build the **Lemma-3-independent scaffolding**:
   computable `chooseReduction` (exhaustive `Fin 4` search), `cliffordLookup`/
   assembly skeleton, the `reconWordC` recursion — all parameterizable on
   Lemma 3 as the one remaining input. WINNING-`k` finding (oracle): the
   reducing-`k` SET is determined by `(x mod 2, y mod 2)` GIVEN realizability
   (0 inconsistent / 16×16 buckets), but `resSqrt2` (mod √2, 4×4) is too coarse
   (inconsistent) — so the dossier's "residue mod √2" `chooseReduction` sketch
   is imprecise; the real selection needs ≥ mod-2 data.

4. ✅✅ **Lemma 3 SHIPPED** (`KMMLemma3.lean`, `69a7842`) — DEEP-RESEARCH UNBLOCKED
   (`Lit-Search/Phase-6x/6x — KMM + Ross-Selinger PROOF MECHANISMS…md`). The
   key reframing: KMM's proof is **NOT** a 𝔭-adic case split (none is published)
   — it is **Algorithm 2**, an exhaustive computer check over `ℤ[ω]/(2³) =
   (ZMod 8)⁴`. `kmm_lemma3_alg2` reproduces it as `native_decide`:
   `∀ x y : Coord4, ∀ j:Fin 2, gde x=j → gde y=j → Pform x+Pform y=0 →
   Qform x+Qform y=0 → ∀ s:Fin 3, ∃ k:Fin 4, gde(add x (mulOmegaPow k y))=(s+1)+j`.
   `P=a²+b²+c²+d²`, `Q=ab+bc+cd−ad`, `mulOmega=⟨a,b,c,d⟩↦⟨b,c,d,−a⟩`,
   `gde=min(4,2·min(v₂P,v₂Q)+[v₂P>v₂Q])` — ALL oracle-validated in our convention
   (0 mismatch over 65535 residues; Alg2 FAILS=0 over 393216 pairs; caught+fixed
   the DR's loose `mulOmega` labeling). `native_decide` ~497s, carries
   `Lean.ofReduceBool` (KMM's own proof is computational — "we implemented
   Algorithm 2, result is true"). **Bridge ring identities SHIPPED**
   (`KMMLemma3Bridge.lean`, `4a6e8ed`): `coordOf`, `normSq_d/_c`,
   `Pform_coordOf`/`Qform_coordOf` (residue forms = `normSq` coords mod 8),
   `coordOf_omega_mul`. **NEXT (bridge cont'd):** the gde-value bridge
   `Coord4.gde (coordOf x) = min 4 (gdePeel (normSq x) fuel)` — formalize KMM
   Prop 1 (the `v₂` closed form + mod-8 determination; validated, gdeMod8==peel
   0 mismatch). Then: Lemma 3 (residue) ⟹ actual `gde(|x+ωᵏy|²)=gde(|x|²)+3`
   for the reducing k ⟹ `sde` strictly decreases ⟹ `chooseReductionComp`
   succeeds (fuel-sufficiency, integration plan B) ⟹ discharge (D) ⟹ Item G.

   --- (historical, superseded by the above) ---
   **Lemma 3** — CORRECTED CONDITION (numerically validated 2026-05-29 via
   `scripts/kmm_zomega_reference_oracle.py`; my earlier `2∣(x+ωᵏy)` note was a
   `gde(element)`-vs-`gde(|element|²)` conflation, FALSE for realizable pairs —
   12032/18304 fail it). The algorithm tracks `sde(|z|²)`, and the s=−1 step
   sends `z' = (z+ωᵏw)/√2`, with `sde(|z'|²) − sde(|z|²) = 2 − Δgde` where
   `Δgde := gde(|x+ωᵏy|²) − gde(|x|²)`. So the reduction needs **∃k∈{0,1,2,3}:
   `gde(|x+ωᵏy|²) = gde(|x|²) + 3`** (Δgde=3 ⟹ s=−1). Oracle confirms: for ALL
   18304 realizable columns (`|x|²+|y|²=2^a`, a≥2, √2∤x,y), the achievable set
   `{Δgde : k∈0..3} = {1,2,3}` EXACTLY (so all of s∈{−1,0,1} via Δgde∈{3,2,1};
   matches KMM verbatim). **NO mod-2 `decide` shortcut exists** — the gde-of-
   squared-norm arithmetic (Lemma 5 + Prop 1 + the `gde(|x|²)∈{0,1}` case split)
   is irreducibly required. Build path: gde-of-`normSq` (via `gdePeel` on the
   real `normSq` element) → Prop 1 parity → Lemma 5 (`normSq_add` cross-term) →
   the {0,1} case analysis. Validate every Lean gde step against the oracle.
5. ✅ S/Z-compressed reconstruction syllable `reconWordC` (≤4 gates/step,
   `interp_reconWordC_mul`/`_eq`) — SHIPPED (`360023c`). Enables the `4·k` step.
6. ✅ `chooseReductionComp` SHIPPED (`KMMCompute.lean`, `ca1ad83`) — computable
   `Fin 4` search over `sdeC`; `chooseReductionComp_reduces` (by-construction sde
   decrease) + `interp_reconWordC_reduceStep` (step correctness). Runtime ring
   computes (`native_decide`/`decide` examples pass). Its EXISTENCE-success when
   `sdeC≥4` is Lemma 3 (DR-gated). [Selection rule is `sdeC`-comparison, not the
   imprecise dossier "residue mod √2".]
7. `cliffordLookup` / 𝕊₃ coverage (`sde(|z₀₀|²)≤3` realizable → word ≤ N₃).
   **N₃ COMPUTED = 9** (2026-05-29, `scripts/kmm_n3_bfs.py` BFS over the
   Clifford+T group, generating set {H,S,T,X,Y,Z,ω}; `sde(|z₀₀|²)≤3` orbit =
   **1664 matrices**, saturating at word-length 9 ≪ depth-14 exploration ⟹
   converged). Matches the dossier's "Clifford suffix ≤ 9 gates". NB
   `sde(|z₀₀|²)` takes values {0,2,3,4,…} (never 1) — consistent with `gde≤1`.
   This cross-checks DR Q2; the 1664-entry table is the concrete `cliffordLookup`.
   Still needs the Lean table + its coverage/length proof (a finite — if large —
   `decide`/enumeration; DR Q2's structural detail will guide the cleanest form).
8. `kmmReduce` fuel-recursion assembly (`interp_reconWordC_reduceStep` correctness
   + `reconWordC_length_le_four` length accounting) + discharge `Nonempty
   KMMReduction` — gated on items 4 (Lemma 3) + 7 (𝕊₃/N₃).

**DR-GATED BOUNDARY REACHED (2026-05-29):** all Lemma-3-independent substrate is
shipped (gde foundations, Lemma 4-core, Lemma 5, `reconWordC`, computable
`reduceStep`/`chooseReductionComp`, **`kmmReduceFuel` + correctness
`interp_kmmReduceFuel` + fuel-form length `length_kmmReduceFuel_le`**, and
**`N₃ = 9` computed**). The remaining critical path — Lemma 3 (item 4), the
`cliffordLookup` table (item 7), then assembly+discharge (item 8) → Item G
(orphan #2) — is gated on the DR
(`Lit-Search/Tasks/submitted/20260529_phase6x_kmm_lemma3_proof_mechanisms.md`,
Q1+Q2). Items H/I gated on Q3.

#### POST-DR INTEGRATION PLAN (mechanical once Q1+Q2 land)

**PROGRESS 2026-05-29 (post-Lemma-3 session — 3 new ships, all build-clean):**
- ✅ **gde-value bridge** `coord4_gde_coordOf` (`PropOneBridge.lean`, `29345fb`) —
  see item 1 above. Kernel-pure.
- ✅ **ZOmega-column Lemma 3** `kmm_lemma3_column` (`KMMLemma3Column.lean`,
  `4243201`+`1f3c089`) — the faithful ZOmega-image of `kmm_lemma3_alg2`: for
  `x,y : ZOmega` with `gde(|x|²)=gde(|y|²)=j∈{0,1}` and unit-column congruences
  `(|x|²+|y|²).d ≡ (|x|²+|y|²).c ≡ 0 (mod 8)`, ∀ `s+1∈{1,2,3}` ∃ `k∈{0..3}`:
  `gde(|x+ωᵏy|²)=(s+1)+j`. Inherits the tracked native_decide from Lemma 3.
  Supporting `coordOf_add` / `coordOf_omega_pow_mul` (kernel-pure).
- ✅ **reduceStep column-0 transformation** (`ReduceStepColumn.lean`, `72d662f`) —
  `T_pow_diag` + `reduceStep_zero_zero : (H·Tᵏ·M) 0 0 = invSqrt2·(M₀₀+ωᵏ·M₁₀)` +
  `reduceStep_one_zero`. The new top-left `z'=(z+ωᵏw)/√2` is KMM's s=−1 update;
  `|z'|²=|z+ωᵏw|²/2` is what `kmm_lemma3_column` controls. Kernel-pure.

- ✅ **clearing connection SHIPPED** (`ClearingConnection.lean`, `17f3cb1`) —
  `denExp_normSq_clearing : ∃ x:ZOmega, √2^(denExp z)·z = of x ∧ denExp(|z|²) =
  2·denExp z − gde(|x|²)` (with `lowestDenExp_add_gdePeel : lowestDenExp+gdePeel=
  fuel`, `sqrt2_pow_normSq_clearing : √2^(2s)·|z|²=of|x|²`, `normSq_of`). Bridges
  matrix-entry sde to the ℤ[ω]-gde of the cleared numerator. Kernel-pure.

**✅ FUEL-SUFFICIENCY ASSEMBLY (B) + RECURSION + CONDITIONAL DISCHARGE — SHIPPED 2026-05-29
(15 commits this session). ENTIRE REDUCTION ALGORITHM ASSEMBLED.**
- Bridges (B): Lemma-4-value `gdePeel_normSq_le_one_of_not_dividesSqrt2` (`0842c54`),
  unit-col congruences (`012af75`), clearing connection (`17f3cb1`), reduceStep col-0
  (`72d662f`), gde-value bridge (`29345fb`), ZOmega-column Lemma 3 (`4243201`).
- **μ-decrease engine** (`MuDecrease.lean`, `96309bb`/`5ed1a99`/`99ea92d`): per-entry
  cleared-form (lowest-terms keystone + gdePeel_stabilizes + entry_cleared_form),
  `column_cleared` (denExp M₀₀=denExp M₁₀ for unitary ⟹ ONE common s, no case-split),
  **`mu_decrease`** (M unitary, μ(M)≥4 ⟹ ∃k μ(reduceStep M k)<μ(M); STRICT), μ-selector
  `chooseReductionMu` + **`chooseReductionMu_succeeds`** (fuel-sufficiency proper).
- **realizable⟹unitary** (`UnitaryClosure.lean`, `4cca327`): the recursion's unitarity
  precondition (adjoint anti-hom + gate unitarity decide; term-mode `IsUnitaryT.mul`
  because Mat2 `*` is the heterogeneous Matrix `HMul`, not `Monoid.mul`).
- **μ-recursion** (`KMMReduceMu.lean`, `6f1123d`): `kmmReduceMu` + `interp_kmmReduceMu`
  (correct WITH termination — bottoms at μ≤3 via fuel-sufficiency, base needs only μ≤3)
  + `length_kmmReduceMu` (≤ N₃+4·μ(M) = honest KMM Cor 1).
- **CONDITIONAL DISCHARGE** (`KMMReductionDischarge.lean`, `c487179`): `baseFinder9` +
  **`kmmReduction_of_coverage : coverage ⟹ Nonempty KMMReduction`** (concrete instance,
  all fields proven, NO axiom — Inv #15). The reduction measure decision is plan A.b
  (`μ = denExp(normSq(M₀₀))`); the length_bound field was refactored to the honest
  `N₃+4·sde(|z₀₀|²)` (`af4032d`).

**⟹ ORPHAN #2 REDUCED TO THE SINGLE 𝕊₃-COVERAGE FACT** (the only remaining input):
`coverage : ∀ M, IsCliffordTRealizable M → μ(M) ≤ 3 → ∃ gs, interp gs = M ∧ gs.length ≤ 9`
— every realizable `μ≤3` matrix has a `≤9`-gate word (the finite `1664`-matrix `N₃=9`
`𝕊₃` orbit, `scripts/kmm_n3_bfs.py`). HARD: formalize the BFS-reachability of the `μ≤3`
orbit over the `ZOmegaSqrt2` quotient matrix ring (not directly `decide`-able). Options:
(a) explicit 1664-entry table + per-entry check; (b) `Finset`-orbit + closure; (c)
bounded-BFS function + reachability. Once proven: `kmmReduction_of_coverage coverage`
makes `Nonempty KMMReduction` UNCONDITIONAL ⟹ discharges the `[Nonempty KMMReduction]`
gating ⟹ Item G (closes orphan #2) ⟹ H/I ⟹ Stage 9/10/13.

**✅ DR RETURNED 2026-05-29 → MATSUMOTO–AMANO ROUTE LOCKED (building).**
(`Lit-Search/Phase-6x/"Phase 6x Tier-2 Item F — DR- formalizing the 𝕊₃ base-case
COVERAGE in Lean 4.md"`.) **Verdict: take the MA normal-form route, NOT BFS** — BFS is
*strictly dominated* (closing the connectivity gap KMM never prove ≈ proving MA existence
anyway). MA (Giles-Selinger arXiv:1312.6584): unique normal form, T-count = SO(3) lde
`k_SO3` (Lemma 4.10), bridge Cor 7.11 ⟹ `μ≤3 ⟹ k_SO3≤3` ⟹ canonical word, NO
connectivity. Coverage length bound RELAXES ≤9 → ≤22 (MA-deterministic; our recursion
gives ≤15); N₃≤22 still fits Item G's L≤90<100.

**Architecture (Python-VALIDATED, `scripts/kmm_ma_coverage_validation.py`, over the full
1664-matrix 𝕊₃ orbit):** recurse on **`kSO3`** (Bloch SO(3) sde = T-count, computable);
base `kSO3=0 ⟺ Clifford` (192, tail ≤6); unique syllable `{T,HT,SHT}` lowers `kSO3` by
exactly 1; `μ≤3 ⟹ kSO3≤3`; length `≤ 3·kSO3+6` (coverage ≤15). `μ` and matrix-sde FAIL as
the measure (832 matrices) — only `kSO3` works. Finite-enumeration REJECTED (~`10¹¹`
4-entry box, infeasible for native_decide; MA recursion processes one matrix at a time).

**Shipped (kernel-pure):** `BlochMap.lean` (`2e73f70`, `kSO3` + sanity decides) +
`BlochHomomorphism.lean` (`082ee14`, `pauli_completeness` + `trace_conj_unitary`).
**Remaining:** homomorphism assembly `R(A·B)=R(A)·R(B)` → ma_step (`kSO3` decrease, the
crux, residue native_decide) → Clifford base (`kSO3=0⟺Clifford`) → bridge (`μ≤3⟹kSO3≤3`)
→ `maCoverage` → relax discharge 9→15 → UNCONDITIONAL `Nonempty KMMReduction` → Item G.
Full plan + technical notes (HMul friction, iS²=-1) in memory note
`project-phase6x-ma-coverage`.

The robust shipped pieces make the discharge a short assembly. Concretely:

**(A) Reconcile the reduction measure. ✅ DECISION LOCKED 2026-05-29 (option b).**
`chooseReductionComp` currently lowers the *matrix* sde `sdeC`; KMM Lemma 3 is for
`sde(|z₀₀|²)`. **Re-point to `μ(M) := denExp(normSq(M 0 0)) = sde(|z₀₀|²)`** (the
squared-modulus sde). This is NOT a free choice — it is forced by:
  (1) the KMM paper (arXiv:1206.5236, confirmed via ar5iv): `sde^|·|²(U) =
      sde(|z₀₀|²)`, Cor 1 `n_g ≤ N₃ + 4·sde(|z₀₀|²)`; `sde(|H₀₀|²)=2` but matrix
      `sde(H)=1`, so they differ ~2× and the matrix form is unsatisfiable;
  (2) this roadmap's own KEY CORRECTION above ("must phrase over sde(|z₀₀|²)");
  (3) NO conflicting downstream constraint: downstream length-bound consumers
      reference the Solovay-Kitaev headline FQNs
      (`solovayKitaev_dawson_nielsen_…`, exponent log5/log(3/2)), NOT the KMM
      `N₃+4·sde` formula — the KMM bound is internal to the base finder (F/G).
**Consequence:** the `KMMReduction.length_bound` field (matrix `sde_le M k`,
`≤ N₃+4·k`) is REFACTORED to `≤ N₃ + 4·denExp(normSq(M 0 0))`. `kmmReduceFuel`
correctness + fuel-length are measure-agnostic (no rework); use a `μ`-tracking
selector. [`sde(|z₀₀|²)` ∈ {0,2,3,4,…}; `=2a−gde`, gde∈{0,1}.]

**(B) Lemma 3 → fuel-sufficiency.** Formalize Q1's `∃k:Δgde=3` (via the
`𝔭=(1−ζ₈)`-adic argument the DR supplies) as: `M` realizable, `sde≥4 ⟹
∃k, chooseReductionComp M = some k` (the search succeeds). With
`chooseReductionComp_reduces` (already shipped) this gives strict decrease;
strong-induction on `sde` ⟹ `kmmReduceFuel base (sde M) M` reaches the base only
at `sde ≤ 3`.

**(C) `cliffordLookup` (Q2).** Build the base finder over the **1664-element
`𝕊₃`** orbit (computed) with `N₃ = 9`: `hbase_correct : ∀ M, realizable →
sde(|z₀₀|²)≤3 → interp (cliffordLookup M) = M` and `hbase_len : ∀ M,
(cliffordLookup M).length ≤ 9`. Q2's structural detail guides the cleanest Lean
form (explicit table vs. decidable characterization).

**(D) Discharge.** Assemble `KMMReduction`:
`reduce M := kmmReduceFuel cliffordLookup (sde M) M`; `correct` from
`interp_kmmReduceFuel` + (B)+(C); `N₃ := 9`; `length_bound` from
`length_kmmReduceFuel_le` (`≤ 9 + 4·sde M`) + `sdeC_le_of_sde_le`. ⟹
`Nonempty KMMReduction` discharged, no axiom. Replace the `[Nonempty KMMReduction]`
gating with the concrete instance.

**(E) Item G.** `cliffordTBaseFinder_kmm` at `ε₀=2⁻⁴` via the discharged
`kmmReduce` on a Selinger-2012 hand-supplied `(u,t)`; `L ≤ 90 < 100`
(`N₃=9` benign); re-derive the 3-conjunct unconditional Clifford+T headline.
**Closes orphan #2.**

#### Item G (M5 stub) — KMM-derived base finder integration

**GOAL:** Replace lightweight `cliffordTBaseFinder_constructive` (Finset-enum, exp-length) with `cliffordTBaseFinder_kmm` derived from F's KMM exact synthesis at SK base `ε₀ = 2⁻⁴`, discharging `BaseFinder_length_bounded` with worst-case L ≤ 90 < `skLengthBaseCase = 100` (DR §4.2).

**BOOTSTRAP:** `CLAUDE.md`, this addendum, then:
- DR §4 + §R3 + §R5
- F output (`RossSelinger/KMM.lean`)
- `lean/SKEFTHawking/FKLW/RossSelingerLightweight.lean` — supersede, don't delete
- `lean/SKEFTHawking/FKLW/PerAlphabetConcreteLengthHeadlines.lean`
- `lean/SKEFTHawking/FKLW/GenericConcreteWordLengthBound.lean` — `BaseFinder_length_bounded` definition

**KEY INSIGHT (DR §4.2):** ε₀ = 2⁻⁴ ⟹ L ≤ 12·log₂(1/ε₀) + 42 = 90 (Selinger-2012 deterministic + MA tightening). 10-gate margin under `skLengthBaseCase = 100`. No probabilistic branch needed.

**DELIVERABLES (new `RossSelinger/CliffordTBaseFinderKMM.lean`):**
1. `cliffordTBaseFinder_kmm` via KMM applied to a Selinger-2012 hand-supplied `(u, t)`. (M3 stub: pick first ZOmegaSqrt2 candidate in a bounded grid; full M3 in I.)
2. `…approximates_within_two_ε₀` UNCONDITIONAL.
3. `…length_le_90` concrete bound via KMM + MA.
4. `…BaseFinder_length_bounded` discharging tracked Prop at `skLengthBaseCase = 100`.
5. Re-derive 3-conjunct UNCONDITIONAL CT headline using kmm base finder.

**ACs:**
- M3 stub clearly marked TODO with arXiv:1403.2975 §5 pointer.
- All UNCONDITIONAL; kernel-only.
- `lake build` clean; ~200 LoC; axioms = 0.
- Orphan #2 closed at "real Ross-Selinger base finder" level (modulo M3 upgrade).

**DO NOT TOUCH:** Phase 6y coordination list.

**EXIT:** commit `feat(phase6x-residual-G-M5stub): KMM-derived CT base finder at ε₀=2⁻⁴ with L ≤ 90`.

#### Item H (M3) — Ross-Selinger 2D grid-problem solver

**GOAL:** Ship `gridSolutions : ConvexSet ℝ → ConvexSet ℝ → ℕ → List ZOmegaSqrt2` — the Ross-Selinger two-dimensional grid-problem solver per arXiv:1403.2975 §5 Theorem 2. M3 of the Ross-Selinger arc.

**BOOTSTRAP:** `CLAUDE.md`, this addendum, then:
- DR §2.1 + §2.2 + §M3
- arXiv:1403.2975 (Ross-Selinger 2014) §5 Theorem 2 + §7 algorithm
- D + E + F outputs
- `Mathlib.Analysis.Convex.Basic` — `ConvexSet`
- `Mathlib.Topology.MetricSpace.Bounded` — upright-rectangle setup

**ALGORITHM (DR §2.1):** Given two bounded convex `A, B ⊂ ℝ²` with non-empty interior, enumerate all `u ∈ ZOmegaSqrt2` with `u ∈ A` and Galois conjugate `u• ∈ B`. M-upright case: O(log(1/M)) ops + constant per solution.

**DELIVERABLES (new file `lean/SKEFTHawking/FKLW/RossSelinger/GridSynth.lean`):**
1. `epsilonRegion : ℝ → ℝ → ConvexSet ℝ²` per DR §2.1 (a).
2. `gridSolutions` with the recursive algorithm (ellipse representations + scaling).
3. `gridSolutions_correct` — every output element is in A; conjugate in B.
4. `gridSolutions_complete` — every solution in `ZOmegaSqrt2 ∩ A` with conjugate in B appears.
5. `gridSolutions_length_bound` — solution count and arithmetic-op count per Theorem 2.

**ACs:**
- All computable; `native_decide`-friendly.
- `lake build` clean; ~700 LoC (DR §M3); axioms = 0.
- Cross-validation against `pygridsynth` (MIT) test oracle for ε ∈ {0.1, 0.01, 0.001}, θ ∈ {π/4, π/8, π/16} per DR §R7.

**DO NOT TOUCH:** Phase 6y coordination list. Read-only on D/E/F outputs.

**EXIT:** commit `feat(phase6x-residual-H-M3): Ross-Selinger 2D grid-problem solver per arXiv:1403.2975 §5`.

#### Item I (M5 full) — Full Ross-Selinger compose + cross-validation

**GOAL:** Wire G + H into full Ross-Selinger `compile : SU(2) → ℝ⁺ → List CliffordTGate` with `‖interp (compile U ε) − U‖ ≤ ε` and `L ≤ 12·log₂(1/ε) + 42` (Selinger-2012 deterministic). M5 of the Ross-Selinger arc.

**BOOTSTRAP:** `CLAUDE.md`, this addendum, then:
- DR §2 + §4
- arXiv:1403.2975 §6-§7 (Diophantine + assemble)
- G + H outputs

**ALGORITHM (DR §2.1):** (a) ε-region; (b) grid-solutions (H); (c) Diophantine `t·t* = √2²ᵏ − u·u*`; (d) assemble `U' = [[u, −t*], [t, u*]]/√2ᵏ`; (e) KMM (F).

**DELIVERABLES (new `RossSelinger/Compile.lean`):**
1. `diophantineSolve` per arXiv:1403.2975 §6.
2. `assembleUnitary`.
3. `compile` composing (a)–(e).
4. `compile_correct`.
5. `compile_length_bound` ≤ `12·⌈log₂(1/ε)⌉ + 42`.
6. Replace G's M3-stub with full `compile`-derived base finder.
7. Cross-validate vs `pygridsynth` for ≥ 50 (θ, ε) test cases (DR §R7).

**ACs:**
- All UNCONDITIONAL; kernel-only.
- `lake build` clean; ~300 LoC; axioms = 0.
- pygridsynth-matched up to MA rewrite.
- Phase 6x orphan #2 FULLY CLOSED at deterministic-branch level. Factoring branch + typical-case 3-constant remain optional follow-ons.

**DO NOT TOUCH:** Phase 6y coordination list. Read-only on D/E/F/H outputs.

**EXIT:** commit `feat(phase6x-residual-I-M5): Full Ross-Selinger compile + length bound + pygridsynth cross-validation`.

---

### Tier 3 — Deferred to post-Phase-6y

Lower priority. Gated on Phase 6y closure to avoid stepping on the parallel agent.

#### Item J — M.1 m-generic upgrade

**GOAL:** Upgrade `Matrix.BCH.bchOrder2Cubic_Fin` (Fin d) to `Matrix m m ℂ`-generic for any `[Fintype m] [DecidableEq m] [Nonempty m]`. Ships the substrate-gap lemma blocking it.

**TIER 3 GATE:** Only after Phase 6y Track S closes and parallel-agent consumption of `MatrixBCHCubicMathlibPR.lean` settles. Coordinate before starting.

**BOOTSTRAP:** `CLAUDE.md`, this addendum, then:
- `lean/SKEFTHawking/MatrixBCHCubicMathlibPR.lean` — current Fin-d form + `Matrix.linftyOpNorm_reindex` aux (Phase 6x)
- `lean/SKEFTHawking/SU2BCHBracketClosure.lean` — SU(2) original
- `Mathlib.Analysis.NormedSpace.MatrixExponential`
- `Mathlib.Data.Matrix.Reindex` — `Matrix.reindexAlgEquiv`

**PREREQUISITE LEMMA:** `(reindexAlgEquiv R e) (NormedSpace.exp K A) = NormedSpace.exp K ((reindexAlgEquiv R e) A)` — reindex commutes with matrix exp. Absent from Mathlib4 v4.29.1; this is the substrate gap.

**DELIVERABLES (modify `MatrixBCHCubicMathlibPR.lean`; new `MatrixReindexExpMathlibPR.lean`):**
1. Reindex-commutes-with-exp lemma (its own Mathlib-PR-quality file).
2. `Matrix.BCH.bchOrder2Cubic_m` via `reindexAlgEquiv` to `Fin (Fintype.card m)`.
3. Bridge `bchOrder2Cubic_m_iff_fin`.
4. Worked examples at `m := Fin 2`, `m := Bool`.
5. Document gap to fully-generic-Lie-algebra (original M.1 spec) as follow-on.

**ACs:**
- Reindex+exp commutativity is a standalone Mathlib-PR-quality lemma.
- `lake build` clean; ~200-300 LoC; axioms = 0.
- Phase 6y consumers continue working (Fin-d form remains).

**DO NOT TOUCH:** Phase 6y coordination list at execution time.

**EXIT:** commit `feat(phase6x-residual-J): M.1 m-generic + reindexAlgEquiv⟷exp commutativity`.

#### Item K — Fibonacci constructive ε₀-net

**GOAL:** Ship a constructive ε₀-net for the Fibonacci alphabet per Phase 6t §13.2 Path-A enumeration, matching the T-S′ pattern that Phase 6x shipped for Clifford+T. Removes the existential `Classical.choose` dependence in `FibonacciEpsilonNet.lean`.

**TIER 3 PRIORITY:** Lower than Tier 1/2 — Fibonacci's existential form has been adequate for two years. Ship after Tier 1/2 close.

**BOOTSTRAP:** `CLAUDE.md`, this addendum, then:
- `docs/roadmaps/Phase6t_Roadmap.md` §13.2 — Path-A enumeration spec
- `lean/SKEFTHawking/FKLW/FibonacciEpsilonNet.lean` — current existential
- `lean/SKEFTHawking/FKLW/FibonacciClosureDenseWitness.lean` — unconditional density
- `lean/SKEFTHawking/FKLW/RossSelingerLightweight.lean` — T-S′ pattern to mirror
- `lean/SKEFTHawking/FKLW/GenericEpsilonNet.lean` — `finite_epsilon_net_of_compact_dense`

**DELIVERABLES (new file `lean/SKEFTHawking/FKLW/FibonacciBaseFinder.lean`):**
1. `fibonacciFiniteCover` via `finite_epsilon_net_of_compact_dense` + Fibonacci density + SU(2) compactness (or Item C output if landed).
2. `fibonacciBaseFinder_constructive` — `Finset.choose`-based UNCONDITIONAL.
3. `fibonacciBaseFinder_constructive_approximates_within_two_ε₀`.
4. `fibonacciBaseFinder_constructive_length_bounded`.
5. If a 3-conjunct Fibonacci concrete-length headline doesn't yet exist, ship one via the same pattern as B-RR5/B-RR7.

**ACs:**
- All UNCONDITIONAL; kernel-only.
- `lake build` clean; ~250 LoC; axioms = 0.
- Phase 6x roadmap §"Constructive ε₀-net follow-on" Fibonacci entry closed.
- Project Solovay-Kitaev story: ALL universal alphabets shipped with constructive base finders.

**DO NOT TOUCH:** Phase 6y coordination list.

**EXIT:** commit `feat(phase6x-residual-K): Fibonacci constructive ε₀-net + base finder mirroring T-S′ pattern`.

---

## 2026-05-29 Forward target — Item L: kernel-verified EXACT Clifford+CCZ synthesis (Mukhopadhyay)

**Status:** ✅ **MVP SHIPPED 2026-05-30** (`MukhopadhyayCCZ.lean`, increments 1–4, commits
`5072aef`→`9ba4241`; Stage-13 GREEN inc 1–3, inc 4 in flight) — the "MVP (safe): exact + correct
(kernel-routine matrix equality)" target below. Generating-element grounding `mukGen_Z = CCZ` +
`CliffordCCZGate` ADT + `interp` + composition + general `mukGen` + reflection `G²=I` (`mukGen_sq`) +
`synth_CCZ_correct` (exact-synthesis correctness over the representability submonoid). The **stretch
(CCZ-count-minimality / meet-in-the-middle)** + the channel-rep characterization remain documented
optional follow-ons. (Original status was: ⏳ QUEUED, sequenced after residual-F + Item G — now done.)

**Naming note.** A companion brief proposed "residual-G", but **Item G is already taken**
(Tier 2 `cliffordTBaseFinder_kmm`, the Clifford+T base finder). Using the next free letter,
**Item L**, to avoid a commit-prefix collision (`phase6x-residual-G` ≠ Tier-2 G).

**Target.** Mukhopadhyay 2024 (arXiv:2401.08950) — Toffoli/CCZ-count-optimal **exact**
synthesis for `{H, S, CNOT, CCZ}` on SU(8). Public deliverable = the **kernel-verified math
layer** (`SKEFTHawking.FKLW.*`): channel-representation algebra, the exact-correctness
theorem, and (stretch) the CCZ-count-minimality theorem. Mirrors residual-F's exact-synthesis
genre, one dimension up (SU(2) Clifford+T → SU(8) Clifford+CCZ).

**Why it belongs in the 6x exact-synthesis lineage (not 6z/6z′/6y).**
- Same thesis as residual-F: constructive, minimal-resource **exact** synthesis — NOT a
  density result (density = 6z `{H,S,CNOT,CCZ}` dense in SU(8); academic-completeness = 6y).
  It shares only the *alphabet* with 6z, which it **imports** (6z = dependency, not parent).
- Reuses residual-F's exact-synthesis **methodology** (meet-in-the-middle / terminating
  fuel-bounded reduction, `exactly-representable ⟹ word` lemmas, the
  realizable/clearing/`native_decide` discipline).
- ⚠️ **Honest head-start caveat (public-side assessment):** the reuse is *methodological*,
  not a drop-in. residual-F's concrete machinery — `ZOmegaSqrt2`, `kSO3`/Bloch homomorphism,
  the MA syllable strip — is SU(2)-specific. Item L needs a **new** channel representation
  (the SU(8) ring + number theory) and a new reduction. "Effort comparable to Ross–Selinger
  SU(2)" is plausible *given* the methodology transfer, but the bulk is new substrate.

**MVP / stretch.**
- **MVP (safe):** kernel-verified **exact + correct** — `synth_CCZ_correct : interp (synth U) = U`
  for exactly-`{Clifford,CCZ}`-representable `U`. Reduces to matrix equality (kernel-routine).
- **Stretch (genuinely risky):** the **provably-minimal CCZ-count** theorem (no circuit uses
  fewer CCZs). If intractable in Lean, ship MVP only (still the first kernel-verified exact
  Clifford+CCZ synthesizer).

**How it complements the shipped tiers.** Density (6u–6z) + the residual-F Clifford+T arc
compile *any* target approximately; Item L compiles the *exactly-`{Clifford,CCZ}`-representable
subset* with **zero error** and minimal CCZ count. A full compiler routes each block to
whichever path wins.

**Scope caveats.** Only exactly-`{Clifford,CCZ}`-representable operations (strict subset;
else fall back to the approximate path). Meet-in-the-middle search is exponential in block
size — applied to small blocks, not whole circuits.

**Sequencing.** Start ONLY after residual-F + Item G close (extend mature machinery, not a
moving foundation). DR verdict: original native-CCZ-*approximation* angles KILLED
(decompose-then-synthesize is SOTA); re-aimed at this **exact** target.

**DO NOT TOUCH:** Phase 6y coordination list.

#### Item L continuation (post-MVP): channel rep → reduction → minimality (L.A / L.B / L.C)

> **Status update 2026-05-30 — L.A/L.B/L.C continuation SHIPPED + Phase 6x′ deep layer.** The Item-L
> continuation closed (channel rep `channelRep` + homomorphism, `sde2` + Fact 3.14, `toffoliCost_ge_measure`
> PARAMETRIC; memory `project_phase6x_itemL_continuation_complete_2026_05_30`). The deep deferred layer was
> then scoped + executed as **Phase 6x′** (`docs/roadmaps/Phase6x_prime_Roadmap.md`): **Fact 3.9 ⟹** (each
> Clifford gen's channel rep is a signed permutation) and the **6z CCZ-essentiality converse**
> (`cliffordOnly_not_dense`, Stage-13 GREEN) are SHIPPED; the CCZ diagonal-conjugation identity (C.1) is
> shipped; **Lemma 3.10 + the unconditional `T^of ≥ sde₂`** (discharging `toffoliCost_ge_measure`'s
> PARAMETRIC `hC`/`hCCZ`) remain a documented residual per the 6x′ off-ramp (the `hC` half is
> substantiated; `hCCZ` is gated on the 64-Pauli Theorem-3.8 entry table + an `sde₂`-on-ℂ matrix measure).
> Full MITM minimality (Conjecture 4.8) stays out of scope. The L.A/L.B/L.C plan below is retained for
> provenance.

The Item-L **MVP shipped 2026-05-30** (status block above). The fuller public math layer (§"Public
deliverable": channel-representation algebra + the exact-correctness theorem + the stretch
minimality) has three remaining increments, gated on a deep-research dossier (DR task SUBMITTED
2026-05-30: `Lit-Search/Tasks/submitted/20260530_phase6x_itemL_mukhopadhyay_channelrep_minimality.md`
— the existing material (abstract + this brief) is insufficient for the channel-rep + reduction +
lower-bound *proof mechanisms*, exactly as the Ross-Selinger dossier was needed for Items F/G/I).

- **L.A — Channel representation + Fact 3.9.** Define the channel (Pauli-conjugation) representation
  and prove the exact-implementability characterization (the one-`±1`-per-row/col Clifford criterion +
  its Clifford+CCZ analog). **Re-base `IsExactlyCliffordCCZ` / `synth` on it** (a decidable/structural
  membership, replacing the trivial `∃-gate-word` + `Classical.choose` of the MVP). *This closes the
  honest public-scope gap: the MVP proves correctness without the representability characterization.*
- **L.B — Reduction / decomposition (Thm 3.2).** A terminating reduction (the `kmmReduce` analog,
  termination by the dyadic `sde₂`) synthesizing any exactly-representable `U` into a `{H,S,CNOT,CCZ}`
  word + the **achievability** Toffoli-count upper bound (the analog of KMM `N₃ + 4·sde`).
- **L.C — Toffoli-count MINIMALITY (the stretch).** The `sde₂`-based lower bound. Likely-tractable
  target = achievability + the invariant lower bound (if optimality rests on a monotone `sde₂` like our
  T-count `sde`); full MITM-exhaustiveness optimality is the deepest, possibly-partial piece. The DR's
  Q5 verdict decides scope.

**Substrate reuse (expected, DR to confirm):** the exactly-implementable SU(8) *matrices* live over
`ZOmegaSqrt2 = ℤ[ω][1/√2]` (already shipped); the *channel* rep over `ℤ[1/2]` (dyadic), where `sde₂` is
the `√2`→`2` analog of our shipped T-count `sde` — so the deeper arc is closer to a **port of the
Clifford+T exact-synthesis machinery** than a from-scratch build. Deterministic branch only.

**Execution:** a fresh `/goal` scoped L.A → L.B → L.C, opened after the DR lands + a direct primary-
source read of arXiv:2401.08950. Genuinely multi-session (comparable to the Clifford+T F/G/I arc).

---

### Audit addendum metadata

- **Authored:** 2026-05-27, autonomous-loop agent post-DR-receipt + post-Phase-6y-parallel-audit.
- **Inputs:** Phase 6x roadmap (this file, pre-addendum); Phase 6x completion summary; Phase 6y roadmap; Phase 6y in-flight commit chain (HEAD `66b227d`); Ross-Selinger DR (`Lit-Search/Phase-6x/Ross-Selinger Clifford+T Synthesis- A Pre-Implementation Research Dossier.md`); Explore-agent substrate audit 2026-05-27.
- **Closure metric:** Tier 1 completion closes retrospective-addendum failure modes #4 and #5 in full strength. Tier 2 completion through item G closes Phase 6x orphan #2 at deterministic-branch level. Tier 2 completion through item I closes #2 in full. Tier 3 completion closes items #1 and #5.
- **No new axioms introduced by any goal prompt above.** All ACs preserve `counts.json::lean.axioms = 0`.

---

## 2026-05-30 Tier-2 progress (scope-corrected closure pass)

Per the scope correction (3-agent sweep 2026-05-30; memory `next_session_phase6x_itemG_architecture.md`):
"unconditional" = density + Dawson-Nielsen SK recursion, NOT constructive number theory; the NT arc
(`ℤ[√2]`/`ℤ[√2][i]` substrate `e3cbb03`/`d422153`) is the EXPLICITLY-DEFERRED optional follow-on.
Item I's `compile_correct` = proven SOUNDNESS (Lean) + empirical completeness (pygridsynth).

- **Item I — ✅ CLOSED (orphan #2, deterministic-branch level).** Lean soundness chain shipped +
  Stage-13 GREEN (`79cb10c`): runnable `compile : SU(2)→(k,b)→Option (List CliffordTGate)` +
  `compile_correct`/`compile_correct_grid`/`compileColumn_approx` (RossSelinger/Compile.lean,
  GridCompileCorrect.lean). Empirical completeness: **pygridsynth ≥50-case cross-val** (`4d7f518`,
  `scripts/grid_compile_pygridsynth_xval.py`) — 76/76 (θ,ε) cases ε-approximate AND satisfy the
  EXACT ℤ[ω] det-1 constraint our `assembleUnitary` formalizes (bit-identical convention); head-to-
  head vs project grid_stub 5/5. Addendum in `docs/validation/phase6x_item_I_compile_soundness_stage13_review.md`.
- **Item G — ✅ CLOSED.** `cliffordTBaseFinder_kmm` (RossSelinger/CliffordTBaseFinderKMM.lean,
  `30ea3d9`) lifts Item I into the SK headline's `ρ_CliffT`/FreeGroup picture via the phase bridge,
  killing the U(2)↔SU(2) ±1 sign with an `H·H` correction (`signCorrect`, keystone
  `coe_ρ_CliffT_signCorrect`). UNCONDITIONAL re-synthesis at honest KMM `N₃+4·sde` length
  (`signCorrect_kmmReduce_resynth`) + the soundness lift `_approx`/`_headline`. Length is the HONEST
  KMM bound, NOT the unsound `L≤90` (DR §4.2 fallback). Stage-13 GREEN
  (`docs/validation/phase6x_item_G_kmm_basefinder_stage13_review.md`, `f93f10b`). HONEST SCOPE: the
  fully-unconditional 3-conjunct CT headline already ships via the lightweight density finder;
  the KMM-finder's unconditional-over-all-`U` approximation is gated on the parked grid-completeness
  `t`-coupling.
- **Item H — ✅ CLOSED.** `GridEnum.lean` (`01e0653`) + Stage-13 GREEN (`docs/validation/phase6x_item_H_grid_enumeration_stage13_review.md`):
  the Ross-Selinger §5 Thm-2 upright grid ENUMERATION `gridSolutions1D`/`gridSolutions2D` + `_mem_iff`
  (correctness + completeness: membership ⇔ the four real bounds, both directions) + count bounds.
  Cross-validated vs `pygridsynth.odgp.solve_ODGP` (`scripts/grid_enum_pygridsynth_xval.py`): exact
  solution-set match on 180/180 upright boxes (4851 solutions), with a reviewer mutation test
  confirming the assertion discriminates. The Step-operator efficiency layer + general-convex regions
  are documented deferrals (the runnable optimal-length compile ships via the single witness, Item I).
- **Item L — ✅ MVP SHIPPED (increments 1–4; the roadmap's "MVP (safe): exact + correct" target).**
  `MukhopadhyayCCZ.lean` (`5072aef`→`9ba4241`): (1) grounding `mukGen_Z = CCZ` (Eq.12 `G_{Z₁,Z₂,Z₃}`
  = project's `CCZ_mat`); (2) `CliffordCCZGate` ADT + `interp` (over the shipped SU(8) literal
  generators + `CCZ_mat`) + composition `interp_append`; (3) the GENERAL generating element
  `mukGen p q r` (Eq.12) + the reflection structure `mukGen_sq` (`G²=I` for any pairwise-commuting
  involutions — Mukhopadhyay's defining property), instantiated as `mukGen_Z_sq` (`CCZ²=I`);
  (4) **`synth_CCZ_correct`** — `IsExactlyCliffordCCZ` is a submonoid containing every gate, `synth`
  extracts a witnessing word, and `synth_CCZ_correct : interp (synth U h) = U` is the kernel-routine
  exact-synthesis correctness for ANY exactly-representable `U`. Kernel-pure, 0 new axioms; Stage-13
  GREEN (inc 1–3; inc 4 review in flight). OPTIONAL STRETCH / deferred (not part of the MVP, like
  Item I's NT arc): the MINIMAL Toffoli-optimal synthesis (Thm 3.2 + meet-in-the-middle =
  CCZ-count-minimality), the channel-rep characterization of which `U` are representable (Fact 3.9),
  and the general `G_{P,Q,R}` realized as an explicit Clifford-conjugate gate word.

**Tier 2 ✅ (required scope).** All required Tier-2 deliverables shipped: G (KMM base-finder headline),
H (grid-solver enumeration + correctness/completeness + pygridsynth xval), I (runnable compile +
`compile_correct` soundness + pygridsynth ≥50-case xval — orphan #2 closed at the deterministic-branch
level), and Item L's MVP `synth_CCZ_correct`. The optional stretches (Item I's NT arc for ∀-target
unconditional completeness; Item L's Toffoli-count-minimality meet-in-the-middle) remain documented
follow-ons, not required for Exit.

Counts at this pass: 9808 theorems / 0 axioms / 0 sorry / 739 modules; build clean (8988 jobs);
`axiom_closure_allowlist` + `counts_fresh` + `graph_integrity` PASS.

---

## 2026-05-30 Item L continuation (L.A / L.B / L.C) — SHIPPED at achievable scope

Fresh `/goal` opened after the Mukhopadhyay DR dossier landed
(`Lit-Search/Phase-6x/Phase-6x — Mukhopadhyay 2024.md`; DR task moved to `Lit-Search/Tasks/complete/`).
Three new kernel-pure modules (commits `952294e` → `62ccfd3`, Stage-9/10 sync `8b5e795`); 0 new project
axioms, 0 sorry, no `maxHeartbeats`; counts 9836 theorems / 0 axioms / 0 sorry / 742 modules; build
clean (8991 jobs); `counts_fresh` + `axiom_closure_allowlist` + `graph_integrity` PASS.

**L.A — Channel representation + structural re-base. ✅ SHIPPED** (`MukhopadhyayChannelRep.lean`).
- `channelRep U` (Eq. 27) as the `64×64` matrix over the SHIPPED Phase-6z 64-Pauli basis (`kronK8Basis`),
  with `channelRep_eq_trace` (the `(1/8)·Tr(P_r·U·P_s·U†)` form).
- The **monoid-homomorphism law** `channelRep_one` + `channelRep_mul` (`(UW)̂ = Û·Ŵ`, §3.3); the
  orthogonality of the channel rep of a unitary (`channelRep_isUnit`); the **conjugation-action
  characterization** `channelRep_mulVec_repr` (`Û` is the matrix of `Ad_U` in the Pauli basis — the
  rigorous meaning of "channel representation").
- **Re-base** `isExactlyCliffordCCZ_channelRep_mem`: every exactly-representable `U` has `Û` in the
  finitely-generated submonoid `channelGenMonoid ⊂ GL(64)` (the concrete matrix monoid the reduction
  searches) — a structural NECESSARY condition / certificate, replacing the MVP's opaque `∃-gate-word`.
- **Documented residual** (dossier Q1.4): the full decidable `⟺` converse is NOT available from
  arXiv:2401.08950 (Lemma 3.10 gives only necessary `ℤ[1/2]`-entries; the converse is open). The
  per-generator dyadic-entry refinement (Lemma 3.10, via Theorem 3.8) and the Fact 3.9 `⟺` converse
  (imported from Gosset–Kliuchnikov–Mosca–Russo, arXiv:1308.4134) are the deeper number-theoretic layer.

**L.B — Dyadic `sde₂` + Lemma 3.16 core. ✅ SHIPPED** (`MukhopadhyaySde2.lean`).
- `sde2 q := (-(padicValRat 2 q)).toNat` (Definition 3.13 — the `√2→2` analog of the shipped
  `√2`-`sde`) + `sde2_le_iff`; **Fact 3.14** (`sde2_half_sum_le`): `sde₂((v₁+v₂+v₃+v₄)/2) ≤
  max sde₂(vᵢ) + 1`, the scalar core of Lemma 3.16's per-step `+1` increase bound.
- Structural decomposition / "achievability" = the MVP's existence (`synth_CCZ_correct`) + the
  `channelGenMonoid` membership (L.A). **Documented residual:** the quantitative `N₃+4·sde`
  achievability bound does NOT exist in arXiv:2401.08950 (dossier Q2.4/Q3.3); the terminating reduction's
  correctness-at-optimal-count is the unproved Conjecture 4.8 (not Lean-tractable).

**L.C — Toffoli-count lower bound. ✅ SHIPPED** (`MukhopadhyayToffoliBound.lean`).
- `toffoliCount gs` (CCZ-count of a word) + `toffoliCost U` (min over all exact words = `T^of(U)`) +
  the telescoping mechanism `toffoliCount_ge_measure` / **`toffoliCost_ge_measure`**: for any measure
  `μ` with `μ(1)=0`, non-increasing under Cliffords and `+1` under `CCZ`, `μ(U) ≤ T^of(U)`. Reading
  `μ = sde₂∘channelRep` this is the telescoping **skeleton** from which **`T^of(U) ≥ sde₂(Û)`**
  follows once the per-generator channel-rep bridges (`hC`/`hCCZ`) are discharged — the theorem is
  PARAMETRIC over `μ` (a trivial `μ ≡ 0` also satisfies the hypotheses; the substantive instantiation
  is the documented follow-on, NOT discharged here).
- **Mechanism-check correction of the DR:** the dossier (Q2.3) claimed no `T^of ≥ sde₂` bound follows;
  a direct check shows it DOES, by telescoping Lemma 3.16 from a Clifford base (`sde₂=0`). (Per the
  Item-L guardrail — secondary sources can err; the proof mechanisms are load-bearing.)
- **Documented residual:** the lower bound is NOT proved tight. Full Toffoli minimality (no shorter
  circuit) requires the exhaustive nested meet-in-the-middle search (Lemma 4.5 / §4.2.1) whose
  heuristic optimality rests on the unproved Conjecture 4.8 — NOT Lean-tractable (dossier Q5.3). The
  per-generator bridges that make `T^of ≥ sde₂` unconditional on the concrete channel rep (`sde₂(Ĉ·M) ≤
  sde₂ M` for Cliffords = Fact 3.9; `sde₂(ĈCZ·M) ≤ sde₂ M + 1` = Theorem 3.8.3; dyadic-ness = Lemma
  3.10) are the per-generator entry analyses, the same deep layer as L.A's residual. The DR's
  alternative Theorem 3.6 (`T^of ≥ log₄(|α_max|·c·√M)`) has unspecified constants `c, M` in the source
  and is not cleanly/non-vacuously formalizable without the thesis-level proof detail — the telescoping
  `sde₂` bound is the cleaner, honestly-stated Lean-tractable lower bound and is what we ship.

**Exit posture:** Item L's full PUBLIC math layer is closed at the achievable scope — channel-rep
characterization + structural re-base (L.A); dyadic `sde₂` + Lemma 3.16 core (L.B); the `sde₂` Toffoli
lower bound (L.C). The per-generator channel-rep entry analyses (Lemma 3.10 / Theorem 3.8 / Fact 3.9
converse) and full MITM minimality (Conjecture 4.8) are documented optional follow-ons, not required
for Exit. The runnable/commercial compiler remains the private side (out of scope).

> **Follow-on (scoped 2026-05-30): the per-generator channel-rep analyses are now a staged blueprint —
> Phase 6x′** (`docs/roadmaps/Phase6x_prime_Roadmap.md`). It discharges Lemma 3.10 (dyadic entries),
> Fact 3.9 (⟹), and the `hC`/`hCCZ` bridges that make the L.C `T^of(U) ≥ sde₂(Û)` bound unconditional
> (Phase 2), and as a cross-phase bonus closes the 6z CCZ-essentiality converse (Phase 1). Full MITM
> minimality (Conjecture 4.8) remains out of scope.

# Development Status — GSMM-Compiler MaxEnt Sampler

**This file is the single source of truth for build progress.** It pairs with:
- [BUILD_PLAN.md](BUILD_PLAN.md) — design, milestones, acceptance gates (the *what/why*).
- [GSMM_Compiler_MaxEnt_Sampling_Implementation_Spec.md](GSMM_Compiler_MaxEnt_Sampling_Implementation_Spec.md) — original math spec.
- [.collab/specs/collab-outcome.md](.collab/specs/collab-outcome.md) — locked cross-cutting decisions.

## ▶ How to resume ("continue package development")

1. Read **Current state** below, then the ACTIVE milestone's row in [BUILD_PLAN.md](BUILD_PLAN.md).
2. Run the **Verify current state** commands — trust observed test results, not just the checkboxes.
3. Execute the next unchecked task under the ACTIVE milestone. **Build one milestone at a time.**
4. 🤝 **Math-critical milestones (M2, M4, M5, M6, M7) require a `/collab` adversarial review** as a
   gate step — Codex independently attacks the correctness of the distribution before the gate closes.
   See the protocol + review targets in [CLAUDE.md](CLAUDE.md). Also use `/collab` for unsettled design
   forks and for non-obvious failing statistical tests (debug mode).
5. A milestone is DONE only when its **acceptance gate passes** (tests green + gate criteria met +
   collab review clean where required). Then: check its boxes, advance **Current state** to the next
   milestone, append a **Session log** line, and `git commit`.
6. Keep [BUILD_PLAN.md](BUILD_PLAN.md) authoritative for design. If a decision changes, update it there
   and record it in [.collab/specs/collab-outcome.md](.collab/specs/collab-outcome.md).

---

## Current state

| Field | Value |
|---|---|
| **Active milestone** | 🟡 **M11.5 — release + production-hardening.** **M11.0–M11.4 done** (build-geometry OK 4 → 40 of 40; end-to-end census correct on aerobes, the cost is efficiency). **M11.5(a) DONE** — the dimension-scaled sampling schedule (`schedule.resolve_schedule`, `schedule_mode="pilot_ess"`) is built, keyed, and honest. **(b) release + (c) full 40-strain production census remain.** *The line that read "v1 (M0–M9) complete" was measured on one model and was wrong — see below.* |
| **Status** | ✅ **1005 tests green** (+26). ruff + mypy --strict clean. **M11.5(a) built the dimension-scaled schedule** — MEASURE-FIRST (τ across 9 strains d=34–145 × β∈{0,1,8,16}, **[benchmarks/M11_5_SCHEDULE_TAU.md](benchmarks/M11_5_SCHEDULE_TAU.md)**; reproduces the M11.4 census *exactly* on shared strains) → `/collab` think (3 rounds, AGREE) → build. Chose **pilot-target-ESS (option B)** over a fitted d-power rule (A, *refuted*: exponent not a constant — 1.2/1.6/2.2 median/p90/worst — ±1.5–2× fixed-d scatter, ignores a β-inflation measured to **27×**); doubling (C) deferred. `schedule.resolve_schedule(sampler, transform, scale_pilot)` sizes `n_samples` from the β=0 scale pilot's flux τ (p90); `schedule_mode="fixed"` (default) is the identity — **fixed-mode flux arrays sha256-identical to pre-change**. THE TRAP closed: the *resolved* integer flows into `plan.sampler` → `sample_recipe_key` (non-vacuous keying regression). `run_diagnostics` now reports **flux-level** R̂/ESS per rung with two separate booleans (`ess_target_met` + `convergence_diagnostic_passed`; nonfinite→fail), so a β=0-sized run reports the target *met* at β=0 and *not verified* at high β rather than claiming it. Codex build-diff review: keying confirmed correct, one honesty hole fixed (`max_schedule_sweeps` was enforced in draws not sweeps under thinning). **On branch `m11.5-schedule`.** — Below, the M11.0–M11.3 geometry state: **build-geometry completes on 40 of 40** (was 4 when M11 opened): M11.0 named the solver in the L3 cache key; M11.1 gave `blocked_reactions` a three-state classifier + fully-cold escalation (4→20); M11.2 changed the span gate to `resolution ≤ span_tol` + a build-wide solve session that eliminated every `kUnknown@flux_only` (20→30); **M11.3 gave the reachable-mass-balance certificate a caller-specific dual-witness path** so it reads a `kUnknown` solve's sound duals instead of refusing on the one output it never reads (30→40). Root cause of the whole M11 family: a persistent warm-started HiGHS instance degrades over hundreds of sequential re-solves — its primal path is history-sensitive while its duals stay sound-but-loose. Full reasoning: **BUILD_PLAN §1.6.11**. ⚠️ **The "40" honestly**: the **6 reachability fixes are durable/machine-independent** (the fix removes the failure mode); the **4 previously-deferred** strains (2 *Hafnia*, pumilus, Liquorilactobacillus) pass on this machine as **basis/RNG-marginal** (§1.6.10) and can flip on another basis. ⚠️ **On branch `m11-real-batch` (not yet merged to `main`).** ✅ **M11.4: the full pipeline (rounding → pilots → sampler) now HAS run on aerobes** (d=51/71/145) — samples valid, invariance + monotonicity hold; the cost is efficiency (mixing/`s_J` precision degrade ~linearly with d). |
| **Next action** | 🟡 **M11.5(b) release + (c) full production census.** M11.5(a) is done (above). Remaining, both production-hardening not gates (M11.4 found no correctness defect): **(b)** release — LICENSE, README/docs, a manifest that reads the real `strains.tsv`; **(c)** a full **40-strain production census** through the sampler at `pilot_ess` + a geometry-pilot covariance/eigenvalue study at d=145 + `s_J` under an independent pilot seed. **Deferred from M11.5(a)** (settled by `/collab`, recorded in [.collab/specs/collab-outcome.md](.collab/specs/collab-outcome.md)): the **β>0 schedule handle** — option C doubling, which is *re-run longer in a fresh dir, NOT resume* (⚠️ the spec's "restart guard supports resumption" was **false** — `_already_done` REFUSES a changed `recipe_key`, no RNG checkpoint stored — corrected in the spec); a **dedicated flux pilot** for non-`pilot_sd` configs (today `pilot_ess` requires `energy_scale="pilot_sd"`, a config-time error otherwise); and a **burn-in policy** (τ is the wrong instrument for burn-in — burn_in is left fixed). Deferred, unchanged from M11.3/M11.4: the geometry residues (2 *Hafnia* blocked floor, pumilus √k span floor, Liquorilactobacillus basis-dependent span) and the M11.3 objective-normalization residual (~1e-25). |
| ~~Superseded next action~~ | 🔴 ~~**The span certificate's RNG-marginal gate (BUILD_PLAN §1.6.10)**~~ — **still real, now ranked 3rd of 4 and understood.** §1.6.10's open question is **answered: no**, an inconclusive probe is evidence of nothing about the span (the two failing directions are conclusive when re-probed cold *and* after 30 unrelated solves; 46/46 constructed truncations were detected on **conclusive** probes). It refuses **2 of 40** strains — the *smallest* of the four failures, not the largest. The original text follows. A 3-strain batch returned `['complete','failed','complete']` on **one unchanged model file**; over 16 `model_id`s, **2 fail — 12.5%** — and `model_id` varies *nothing but the RNG stream*. Every run agrees `d=46`, `max_width ≈ 1.85e-12`; the certificate computes the right geometry and refuses to *say so* because 1–2 probes of 214 were noise-swamped. **A 100-strain batch silently returns 88, and `metabolicSubcommunities` is exactly that batch.** ⚠️ *The remedy is a hypothesis until measured* — the question is whether an inconclusive probe on a direction every other seed reads at 1e-12 is evidence of anything, or whether the gate conflates "this probe was uninformative" with "the span may be incomplete" (`complement complete=True` says the sweep was not truncated). **Do not widen the tolerance or retry until it passes** — that is choosing the bar to get the verdict (§1.6.7 round 4 rejected exactly that once). Then: the **`certify_reachable_mass_balance` LP formulation** (Carried, below — same disease, different certificate); a **metadata digest in `cache.ArtifactCache`** (it hashes every array and *trusts the meta*; M10.2e's `numerical_identity` re-derives its `recipe_key` rather than trusting it, which is the pattern); β→performance calibration (spec §22.3); the β>0 kernel's 18% of unused work (M9); parallel tempering; slice kernel; mode-feature discovery. **Pilot-chain pooling is measured at +0.7% and should be dropped from the list** (§1.6.9). |
| **Blockers** | ✅ **build-geometry now completes on 40 of 40 strains (was 4).** The 6 `kUnknown@reachable_mass_balance` failures are **fixed by M11.3** (durable). The 4 previously-deferred (2 *Hafnia* blocked floor, 1 pumilus √k span floor, 1 Liquorilactobacillus basis-dependent span) **pass on this machine** as basis-marginal (§1.6.10) but are not durably closed — a tighter span certificate / blocked-floor guidance is still owed if they refuse on another basis. `kUnknown@flux_only` **0** (was 8), span noise-swamped refusals **0**. All failure modes fail **closed** — no wrong numbers ever produced. Progression: 4 (pre-M11) → 20 (M11.1) → 30 (M11.2) → 40 (M11.3). ✅ **M11.4 ran the whole pipeline on aerobes** (census below) — no correctness defect; the open work is a dimension-scaled schedule (efficiency), not a gate. |
| **Carried, not chased** | ✅ **The span certificate's 12.5% refusal (§1.6.10) is FIXED by M11.2.** ✅ **`certify_reachable_mass_balance` is FIXED by M11.3** — the caller-specific dual-witness path reads a `kUnknown` solve's sound duals (`solve_dual_witness` on a narrow `LPDualWitness`, whitelist `{kOptimal, kUnknown}`, exact `.name` match), without loosening `HighsLinearProgram.solve()`. Premise measured on all 6 strains first: only `kUnknown` arises, duals dual-feasible and 8-digit-tight, CERTIFIED 12–27× inside 1e-9. 🔴 **Deferred (conceded real, Codex):** the dual-independent objective-normalization residual in `_reachable_extreme` (`Σ|E_i − ‖E_i‖·unit|·Ω` + final outward rounding) — measured ~1e-25, ~16 orders below the contract, its own small hardening step. **The M11 root cause unifies all of this**: warm-started HiGHS instances degrade over many re-solves (primal path history-sensitive, duals sound-but-loose), and gates that consult a primal-quality signal to veto a dual-based claim refuse valid inputs. |
| **Last updated** | 2026-07-18 |

### 🔴 Settled by M11: **v1 was measured on a sample of one — and it is the only anaerobe of the 40**

**`models/` holds one file, and the batch is 40.** *Bifidobacterium adolescentis* is the **only
anaerobe** among the curated strains; the other 39 are aerobes, the first one measured having **479
free reactions to Bifido's 260**. Every measured premise in this repo — d = 46, 214 probes, §1.6.10's
"12.5% of strains", the worker sweep, §1.2's "at d≤55 sequential wins by default", the 1.93×
overlap asymptote — is a property of **that one organism**. This tracker diagnosed the gate-fragility
*pattern* with real precision across four instances and then measured its *incidence* on n=1.

Swept `build-geometry` over all 40: **4 succeed.** The full table and mechanism are in **§1.6.11**.
**The item this file ranked #1 (the span certificate) refuses 2 of 40 — the smallest of four
failures — and the two largest (24 and 9) were recorded nowhere.** Nothing here produced a wrong
number: all four fail closed, and the blocked/moving guard was *protecting* the distribution.

**The mechanism, after three `/collab` rounds in which I conceded 13 points and had two remedies
killed** (Codex's wording, narrower than mine, because my "good duals" is falsified by this
milestone's own data):

> **Primal quality is history-sensitive under warm starts, while these dual constructions stay sound
> independently of it — but their *tightness* varies, and must be judged by the resulting bound.**

**Two necessary causes, and the second is a design defect a perfect solver would not fix.**
`dual_upper_bound` *deliberately* promises soundness for arbitrary duals — so a loose certificate is
an **anticipated input**. But `blocked_reactions` reads `U > blocked_tol` as **"moving"** when it
licenses only *"not certified blocked by this dual."* **Two states where three exist.**

**Both of my remedies were wrong, and both died on evidence rather than argument.** I proposed
deriving `blocked_tol` from `dual_upper_bound`'s rounding allowance, having claimed the offending
3.38e-9 *was* that allowance — measured, it is **1.3%** allowance and **98.7% raw bound**, so the
derived bar would sit at 4.5e-11 and the reaction would **still** classify as moving. *The remedy
would have failed outright.* And I proposed simply dropping `n_inconclusive == 0` — which would have
made the certificate **unsound**, because `exhaustive` bounds the resolution **nowhere**. **I also
committed this file's own recorded primal-lower-bound error** (arguing a reaction "does not move"
from a negative primal width) *against a warning printed ten lines above the code I was reading* —
M4 wrote it, M9 walked into it (§1.4.2), and M11 makes three.

**M11.0 is done and it was forced first**: `geometry_cache_key` now names its solver
(`highs_backend.solver_identity`). Every remaining fix changes solve bytes, and without it a bumped
`BACKEND_IMPL_VERSION` was a cache **hit** that then died on the content key — where §1.1 requires a
miss — while the **HiGHS version was in neither identity**, so a `uv sync` silently served another
solver's geometry. Found by Codex, not by me. **And the full suite caught a bad test of mine**: it
passed alone and failed in the suite because it asserted `'highspy' not in sys.modules` — global
interpreter state, not a property of the key. M10.2d's cobra test already says why, in its own
docstring: *"In a subprocess, because a module another test already imported would make this pass for
free."* Rewritten as a subprocess test and **proved non-vacuous by sabotage**.

### ✅ Settled by M10.2c: **the mandate was real — and the *default config* would still have sent it to the wrong lever**

**`run_batch` now overlaps** (§1.6.9): 131.6 s → 93.1 s at M=3, draws bit-identical. And for once
this tracker's "§1.2 mandates it" claim was **true** — a top-level bullet whose subject *is* batch
scheduling, against a `for spec in specs` loop that prepared, submitted and drained in one breath.
**But "the plan mandates it" was still not sufficient reason to build it, and that is the lesson.**

**The arithmetic decides which term the remedy attacks, and it inverts between two configs:**

| | `betas=(0.0,)` — **the default** | 8-rung ladder — **production** |
|---|---|---|
| `P` prepare (parent, **1 core**) | 23.1 s | 23.1 s |
| `S` sampling (pool, **14 cores**) | **1.3 s** | **21.5 s** |
| overlap is worth | **~5%** | **1.93×** |

**Measure the default and you build the wrong thing.** At `betas=(0.0,)` the pilots are **86.7% of
`prepare_model`** (20.1 s of 23.1 s) — 8 chains walking one at a time in the parent while 13 cores
idle, and `run_chains`' own docstring says they are poolable and that a pool "draws the *same
numbers*". Everything points at pooling the pilots. **I believed that for an hour.** At the ladder the
package exists to run, `P ≈ S` and it reverses: **once prepare overlaps sampling the pilots are free —
hidden behind the pool** — so pooling them adds **0.7%** (23.1 → 22.9 s/model against a 23.2 s
all-cores floor), while overlap alone lands *on* that floor. The tracker's recorded "the two-phase
pool dispatch is the **weaker** remedy" was **right, for a reason it never stated**. *Two levers on the
same 20 s differ by 100× in value depending only on what else is running.*

⚠️ **And the headline is M-dependent — quoting 1.93× alone would be M6's "12×" error again.** Only the
last model's sampling has nothing to hide behind: `speedup = M(P+S)/(M·P+S)` gives **1.32× at M=2,
1.47× at M=3, 1.77× at M=10, 1.91× at M=100**. The measured 1.41× at M=3 is **96% of what M=3 allows**,
not 73% of 1.93×. *Both arms were measured; neither was predicted.*

**Two process notes worth keeping.** (1) **My prediction was wrong and only the measurement caught it**:
from the per-unit cost I expected `S ≈ 4 s` at the ladder; it is **21.5 s**, because β>0 units cost ~7×
a β=0 unit. (2) **The non-vacuity probe earned its keep instantly** — the first lookahead-depth test
**passed on the serial code**, because with two specs depth-1 and depth-2 emit identical event orders.
It takes **three** specs to see the difference. M10.2e's rule generalizes: *a test that cannot fail on
the broken code is not evidence, and "it passed" is exactly how it hides.*

### ✅ Settled by M10.2e: **2.7e-15 of BLAS noise decided whether the package ran** — and two of these four findings are still open

**Fixed.** `maxent sample` completes from a clean cache under default threading; the basis and `T₀`
are the same bytes at any ambient thread count (proved by a test that reproduces the defect through
`build_geometry.__wrapped__` *before* asserting the fix, so a thread-invariant CPU skips rather than
passing hollowly). It cost nothing: pinning is **21% faster**, a 260×46 Gram-Schmidt being far too
small for 14 threads to repay their dispatch overhead. Full reasoning: **BUILD_PLAN §1.6.8**.

**What follows is the original diagnosis, kept because findings 3 and 4 are still live.** It **failed
closed** — M9's certificate refused to sample rather than sampling something wrong — so **no
incorrect numbers were ever produced.** The measured chain, end to end:

| `OMP_NUM_THREADS` | basis | Δ vs 1-thread | pilot draws Δ | `T₁` cond | `certify(T₁)` |
|---|---|---|---|---|---|
| **1** | `d35fe4fccf` | — | — | 5969 | **3.873e-11 OK** |
| unset / 2 / 4 / 8 | `970f8dddac` | **2.7e-15** | **2.601** | **5352** | 🔴 **kUnknown** |

**Every step of that is worth stating separately, because they are four different findings.**

1. **The L3 artifact is not a function of its key.** One key (`e9d6fc28673a`), two bases. The support
   points are identical — HiGHS is pinned to `threads=1` — while the basis is NumPy/BLAS
   (`residual -= basis @ (basis.T @ residual)`, the Gram-Schmidt re-orthogonalisation), and
   multi-threaded BLAS reduces in a different order. §1.1's rule, violated in v1's own geometry.
2. **The two bases are the same basis.** They differ by **2.7e-15** and span the same subspace to
   2.7e-15 — a few ULPs. Identical M4 span certificates (`max_width` 1.80e-12, 0 inconclusive), same
   d = 46, same `cond(C_q)` 1.537e4, both `T₀` certify. Nothing here is *wrong*.
3. **The pilot amplifies 2.7e-15 to 2.601 — O(1) on a coordinate range of [−2.48, 1.95].** That is
   not a bug; it is an MCMC being chaotic. But it means `T₁`, `s_J` and the whole β axis are
   sensitive to the **last bit** of the basis, at a gain of ~10¹⁵. Reproducibility of the geometry is
   therefore not housekeeping — it is the precondition for the pilot DAG meaning anything twice.
4. 🔴 **And the `T₁` that fails certify is *better conditioned* than the one that passes** (5352 vs
   5969). So the failing draw cannot be called unlucky geometry: **`certify_reachable_mass_balance`
   is fragile**, and this is M9's own lesson resurfacing in M9's own replacement gate — *a bar a
   valid input clears only 2 times in 3 is not a tolerance, it is a coin flip.*

**So pinning the threads (M10.2e) fixed finding 1 and *hides* finding 4; it does not fix it.** Another
seed, model or machine can still land on a `T₁` the certificate cannot solve. Chasing that was
**deliberately deferred** — see **Carried, not chased** above, and it needs `certify`'s LP
formulation looked at, not the thread count. Finding 3 is not a defect and cannot be fixed; it is why
finding 1 mattered.

🔴 **And the R̂ half of this was never a threading problem at all — M10.2e's own framing was wrong
until it was measured.** Pinning the threads made `test_the_chains_mix_and_the_diagnostics_say_so`
fail (R̂ 1.1654 vs 1.15), which reads like the fix breaking a test. Measured across **8 seeds** at the
fixture's own 1500 draws: R̂ spans **1.089–1.177** and min ESS spans **10.2–50.7**. The bars sat
*inside* the distribution of valid runs — 2 of 8 seeds fail, and seed 0, the fixture's own, fails
**both** (its ESS failure was hidden behind the R̂ assertion that runs first). **The thread count was
never the cause; it was one way to toss a coin that seeds toss just as well.** Fixed by the
**schedule**, since R̂ → 1 as the chain grows is a theorem: at 4000 draws R̂ is 1.033–1.059 and min ESS
59.7–155.0 across 5 seeds — the same bars, now with 2.5× and 3× margin. *A bar a valid input clears
only 2 times in 3 is not a tolerance, it is a coin flip* — M9's lesson, third time.

⚠️ **Cross-machine bit-reproducibility is not achievable and should not be promised.** This NumPy
ships OpenBLAS `0.3.31 DYNAMIC_ARCH … neoversev2`, which selects kernels at **runtime by CPU
detection** — so a different CPU can produce a different last bit at the *same* thread count, and
finding 3 amplifies it. `s_J = σ̂₀` is therefore reproducible **in distribution, not bit-for-bit**,
across machines. That is not a new correctness problem: M10 already reports it as calibration
uncertainty (±2.6% relative SE, §1.6.6) — a different machine's σ̂₀ is another honest draw from the
same pilot law. It does mean the L3 key can honestly promise *"the same inputs on this machine"*, not
*"these bytes anywhere"*.

**Why nobody noticed:** every recorded CLI verification — including mine for M10.2b — reused a cache
warmed by a **threads-pinned probe**. This file's own "Verify current state" command failed from a
clean state, and nobody ran it from one.

🔴 **And here this tracker must correct itself, because the first thing it wrote about this was
wrong.** It claimed "§1.2 already mandates the fix and the code disagrees — the fourth time". **It
does not, and there is no drift.** §1.2's thread rule is a *sub-bullet of "Sampling: process pool over
`(β, chain)` units"*, and its own parenthetical states its reason: "the real oversubscription risk **in
solver-free workers** is BLAS/OpenMP". It is a **worker resource-control** policy, and it is
**implemented and works** — `run_batch` calls `_limit_thread_env()` *before* creating the spawn pool,
so each worker's freshly-imported NumPy inherits the pinned env exactly as §1.2 asks. (Codex, M10.2e
review: the pool `initializer=` is the redundant part, not the parent call.)

So this is **not** the "BUILD_PLAN settles it, the code drifted" pattern — it is a **gap in the
plan**: nothing ever required *parent-side geometry determinism*. Worker oversubscription (a
performance concern) and geometry reproducibility (a correctness concern) are **two requirements that
happen to share one mechanism**, and treating them as one is what let the second go unstated for ten
milestones. **I pattern-matched a rule onto a case it does not cover, in the session where that rule
had just paid off three times** — which is this repo's own recorded failure mode about confident
prose, committed while recording it. The one real §1.2 discrepancy is smaller and separate:
`_limit_thread_env` uses `os.environ.setdefault`, so it does **not** enforce one thread when the
caller already exported four.

### 🔴 Settled by M10.2d: **L0 is cached — and a warm run no longer imports the parser**

With the pilots keyed, warm `prepare_model` was **1.21 s and essentially all `load_canonical_model`**
— a stage `cache.py`'s own docstring and this file both described as cached, and which nothing
stored. M9's "the code never implemented its own documentation", a third time. Now **0.645 s**, with
`T₁` and `s_J` bit-identical.

**The arithmetic set the scope, as it has every time — L0 only.** §1.1 names a *four*-layer DAG;
measured warm, `.reduce()` (L1) is **1 ms** and the objective + LP (L2) is **45 ms**, against
`load_canonical_model`'s **1.157 s**. Keying a 1 ms stage is §1.6.7's "16.4× upside-down" mistake with
new numbers. **The numbered layers describe the dependency structure; they are not a shopping list of
stores.** Three layers are live: `L0`, `L3`, `pilot`.

**L0 needs two keys, and that is not a hedge.** M8 settled that its identity is *content*-addressed —
and you cannot fingerprint a model's contents without parsing it, which is the thing being skipped.
So `model_lookup_key` is a function of the **inputs** (`hash_file`: 1 ms) and `l0_key` stays the
authority, **re-derived on every load**. That split is also what makes it safe to put the reaction
IDs in `meta`, which `ArtifactCache` does not hash: tamper with them and the re-derived key moves.

🔴 **The prize was bigger than the parse, and the key had to be designed for it.**
`load_canonical_model` is **1.157 s** on the first call and **0.52 s** after: the gap is cobra's own
**0.65 s import**, *54% of the cost*. A cache that skipped the parse and still read
`cobra.__version__` for its key would recover barely half of what it was built for.
`provenance._installed_version` reads package **metadata**, and `load_model` imports cobra lazily —
so **a warm run never imports cobra at all** (`'cobra' in sys.modules` is `False`, pinned in a
subprocess). The L0 hit costs **4 ms**.

⚠️ **The lookup key hashes the resolved source path, and that is not redundant with the file's
sha256.** `build_canonical_model` falls back to `source.stem` when a model carries no `id` — so two
identical files under different names are two different `model_id`s, and **`model_id` keys the RNG
streams**. A key over the bytes alone would serve one strain's IR under another's name. Two copies
are parsed twice instead: a false miss costs 0.5 s, a false hit corrupts.

### 🔴 Settled by M10.2b: **the pilots are cached — and the gate is *before* the dispatch, not inside it**

The DAG's expensive node finally sits behind its key. Measured on the example model:
**`prepare_model` 23.08 s → 1.17 s warm (19.6×, 21.9 s of serial parent work removed)**, with `T₁`'s
key and `s_J` **bit-identical** cold vs warm vs no-cache (`s_J = 2.520009578949248` exactly), and
19 MB of cached pilots against the 19.6 MB the payload split predicted.

**The highest-risk line in the diff is one the natural implementation gets wrong.** Wiring it as
`get_or_compute(layer, key, lambda: run_pilot(...))` leaves `require_certified_transform` inside the
`compute()` closure — **which runs only on a miss**. That is M10.2a's defect verbatim (M9's
mass-balance gate lived in the `compute()` closure of `_load_or_build_geometry`). So the gate runs in
the caller, before the dispatch, and the builders keep their own. **Proved rather than asserted**:
moving it back inside `compute()` makes `test_a_cached_pilot_still_refuses_an_uncertified_transform`
fail with *DID NOT RAISE*, while the two miss-path gate tests stay green — which is exactly why the
hit-path test has to exist.

**A `/collab` round-1 argument killed my design and it was the good kind of kill.** I opposed the
recorded payload split (geometry→coordinates, scale→fluxes) because it destroys both tests that
"prove the pilots are independent". Codex: `not np.allclose(a, b)` proves **non-identity, not
independence** — the tests' names overclaimed — and the property they named *is not even true*, since
`T₁` is derived from the geometry pilot, so the scale pilot depends on it through its own frame. What
is independent is each pilot's **RNG stream given its inputs**, and the direct evidence is the
**spawn key**, which `run_chain` already records and `NeutralPilot` **discarded**. So M10.2b stores
the spawn keys and *recomputes* the expected ones on every construction: **M10.2a's bug (`stage`
hardcoded to `"sample"`) would now raise on the first pilot ever built.** Codex then talked me out of
the flux fingerprint *it had proposed* — a digest of the geometry pilot's discarded fluxes is an
unrederivable assertion in trusted meta. **Evidence you recompute is evidence; evidence you store and
read back is a claim.**

### 🔴 Settled by M10.2b: **the hole behind the repair was *in* the repair** — round 3, again

The M10.2a review's lesson held verbatim: `/collab` round 3 opened **DISAGREE on the built diff** and
found a defect M10.2b had just introduced. **Hoisting the certificate gate out of `compute()` left
the polytope relation behind in `_run_pilot_chains` — on the miss path only.** I had probed for
exactly this and my probe passed, because I used an *honest* wrong polytope, which changes the keys
and is caught three other ways. Codex's attack is the one that works:

```python
liar = dataclasses.replace(transform, polytope_key="a-polytope-this-transform-never-met")
```

`RoundedTransform.content_key` hashes `geometry_key`, `transform`, `center`, `ridge` — **not the
transform's own `polytope_key`**. So the lie keys *identically*; the certificate gate passes (both of
its comparisons are against unchanged values); the pilot is served. **Executed: with an empty cache
the call refuses, with a warm one it returns a pilot.** *A cache hit accepted what a miss refused — in
the milestone whose entire subject is that it must not.* Fixed by making `require_pilot_inputs` the
one place both paths ask: **hoisting one of two checks is how the first version closed an asymmetry
while claiming to have closed the asymmetry.** The regression test fails on the shipped code and
passes on the fix.

Three further overclaims of mine that Codex refused, all now narrowed rather than defended:

- **The spawn-key guard proves less than its docstring said.** `stream_seed` puts `seed` in the
  `SeedSequence`'s **entropy**, and only the four semantic coordinates in its `spawn_key` — so a
  regression hardcoding `config.seed` sails through. The guard checks the *semantic coordinates*, not
  the whole stream; `run_chain` never records the entropy, so it cannot honestly reach further.
- **"`_frozen` is the pilots' only array constructor" was false.** It ran in `run_*_pilot` and
  `from_bundle` — the two *well-behaved* constructors — while plain dataclass construction produced a
  mutable pilot. An invariant two callers agree to uphold is a convention; `__post_init__` now
  normalizes, so it is a property of the **class**. `from_bundle` also never checked the payload's
  shape against the recipe's own `n_chains × n_draws`.
- **The `CALIBRATION_IMPL_VERSION = 3` rationale was simply wrong.** It claimed to prevent a v2/v3
  collision; `content_key` passes `feasibility_tol` as a *named component*, so v3 keys already differ
  — and no v2 pilot was ever stored, M10.2b being the milestone that wires the store. Kept as
  bookkeeping with an honest reason: *a version constant defended by a false argument is worse than
  one defended by none.*

Also found and fixed: **the pilots ignored `geometry.feasibility_tol`** — `run_chains` was called
without it, so they silently used the 1e-9 default while production used the configured value. It
reaches start selection, chord construction and refresh validation, so it moves the draws. The key
was *complete* while the tolerance was a hardcoded constant and becomes a **false-hit generator** the
instant the pilot honours the config — which is why both halves land together. And **the log
announced a 19.3 s pilot on a 40 ms cache hit**: a manifest describing work that did not happen, this
package's signature bug in miniature, found by reading the CLI's own output.

### 🔴 Settled by M10.2a: **an artifact must be a function of its key** — and four of them were not

The tracker recorded M10.2 as blocked on "a real fork BUILD_PLAN does not settle". **It was not a
fork; it was plan/code drift, and the arithmetic nobody had done says so** — the M10.1 lesson
repeating one milestone later, in this file's own prose.

| stage | measured (Bifido, d = 46, serial) | cached? |
|---|---|---|
| `build_geometry` (~1100 LPs) | **1.168 s** | yes — as `T₀`'s bundle |
| the two β=0 pilots | **19.202 s** | **no** |
| `reround_transform` → `T₁` | **0.009 s** | no |

A new layer for `T₁` would exist to avoid rebuilding a **1.17 s** stage while costing **19.2 s** to
fill — **16.4× upside-down**. And §1.1 has *always* said L3 holds "**B**, support_points, center, L,
T, dimension, **span certificate**": `to_bundle` held no `B`, no `s`, no certificate, and
`ReducedGeometry` had **no serializer at all**. M9's "the code never implemented its own
documentation", one layer up. Rule: **cache what is expensive, derive what is cheap, key everything.**

**The through-line — §1.1's asymmetry, *a false miss only recomputes; a false hit corrupts* — means an
incomplete key is strictly worse than none.** Asking "is this artifact a function of its key?" of
things this repo already had returned **no** four times. Full reasoning: **BUILD_PLAN §1.6.7**.

- ⚠️ **The neutral pilot was objective-dependent and its docstring denied it.** `calibrate` fed both
  β=0 pilots `optimum_coordinates` — from the objective's own LP optimum — while `NeutralPilot`
  claimed "**objective-independent** … one neutral pilot serves every objective on a polytope" and
  hashed neither. Measured, two pilots differing in *nothing else*: **identical `content_key`**, max
  |Δy| = 2.79, `T₁` cond 7198 vs 9663, `s_J` 2.6287 vs 2.4995. **Not bias** — both are honest draws
  from one β=0 law and the gap is Monte Carlo noise; the defect is that **the artifact was not a
  function of its key**, so M7's two-objectives-on-one-polytope case takes the first hit and never
  knows. Codex's mechanism beat mine: the hint changes the support hull's cardinality → the Dirichlet
  draw's dimension → **RNG consumption on every later transition**; the streams *desynchronise*. Fixed
  **structurally** — `run_neutral_pilot` has no such parameter. M10.1 had shipped that hint with **zero
  test coverage**: removing it broke no test.
- 🔴 **M9's mass-balance gate was bypassable through the package's own cache-warming path** (a **v1**
  defect). It lived only in the `compute()` closure of `_load_or_build_geometry` — which runs **only on
  a miss**; on a hit nothing read the certificate. And `maxent build-geometry --cache-dir` wrote its
  *own* bundle under `batch`'s key, omitted the certificate, and **stored it after printing REFUSED**.
  Warm, then sample. Two writers of one schema is the defect; `build_l3_bundle` is now the one writer.
- 🔴 **A `COMPLETE` marker named a chain, not an experiment** (a **v1** defect). §1.1 specified the
  sample key from the start; **nothing computed it** — `store_chain` recorded only `polytope_key`. A
  results tree reused after any change that moves the numbers resumed the units it had and sampled the
  rest **from a different law**: two experiments in one tree, stacked into one cross-model table, every
  per-chain diagnostic green *because each chain really is correct*. `sample_recipe_key` now computes
  it; `_already_done` **refuses** rather than recomputing (a results tree is the user's output).
- ⚠️ **`T₁` was sampled uncertified — and must be certified before the *scale pilot***, which is itself
  a chain in `T₁`'s frame. `range(T₁) = range(T₀)` is a theorem, so the *true* worst residual is
  identical — but the certificate is a **numerical** bound over `E = S·T₁` and a fresh `T₁⁺`. Measured:
  `T₁` certifies at **3.86e-11**, inside M9's independently measured `T₀` range 3.6e-11 … 5.1e-11.
  *Two certificates, two matrices, no shared computation, agreeing where the theorem says they must.*

**The criterion, because getting it wrong is easy: an artifact key asks "are these bytes the same
artifact?", not "is this the same distribution?"** M10.2 initially excluded `optimum_coordinates` from
the sample recipe by importing M7's target-identity reasoning (§1.6.5) — *while having just fixed the
identical defect for the pilots*. Codex's refutation is decisive: the recipe key already hashes `seed`,
`chain_index`, `schedule` and `storage_mode`, **none of which define the stationary law**. Both keys
are right; they answer different questions.

### ⚠️ Settled by M10.2a: a guard is only as total as its weakest entrance — 4 review rounds, each behind the last

The `/collab` review found the hole behind each repair, in turn, and the sequence is itself the
finding: **don't trust the claim → check the evidence → validate the evidence → own the bar it is
judged against.** M2's "the first fix for a numerical bug is often itself buggy", generalized from
arithmetic to authority.

- **Don't trust the claim.** `is_certified` is *derived*, so `to_cache` stores the fields and the loader
  re-derives — a bundle asserting innocence beside contrary evidence is inexpressible.
- **Then: the evidence was never checked.** A hole in that very reasoning: `from_cache` checked only
  that fields were **present**, so `worst_absolute = −1` sails through (`−1 ≤ 1e-9`) and a *corrupted*
  certificate certified through the mechanism built to stop a *fabricated* one. `__post_init__` now
  refuses malformed evidence.
- **Then: the certificate chose its own bar.** `certify_reachable_mass_balance` accepts any positive
  `contract`, so `contract=1.0` gives a **truthful** `is_certified` that passes the gate — a proof of a
  different and useless proposition, no corruption involved. M9 settled there is **one** declared
  definition of mass-balanced (η = 1e-9, the bar emitted samples meet), so the gate now tests
  `worst_absolute` against **the policy**, and the certificate's `contract` is provenance.
- **And gating an orchestrator does not gate its primitive**: `calibrate` took a required
  `bootstrap_certificate`, and public `run_neutral_pilot` beside it still started the same chain
  uncertified. It takes one too.

**Honest scope**: none of this is adversary-proof — a caller who hand-builds a plausible certificate
defeats any Python-level proof object, and the docstrings say so rather than overclaiming. It closes
the repo's stated corruption model (accidental damage + ordinary API misuse). `ArtifactCache` still
hashes every array and **trusts the meta**; that digest is deferred by agreement as an all-layer
property.

### 🔴 Settled by M10: **a deferred remedy is a hypothesis, not a plan** — M6's recorded cure was wrong

M6 promoted "pilot-based `s_J`" to a **prerequisite** and recorded a remedy, a mechanism and a
magnitude: use spec §22.2's "support **or pilot** points", and the ladder "tilts ~12× harder". **The
diagnosis was exactly right and all three parts of the cure were wrong** — and nobody could see it,
because nobody had done the arithmetic. Measured first:

| candidate `s_J` | value | `dE/dβ|₀` | β to close the gap |
|---|---|---|---|
| **A** `J* − Q₀₅(J(support))` — M6's | 32.51 | 0.183 | 117 |
| **B** `J* − Q₀₅(J(pilot))` — **spec §22.2 literal** | 25.41 | 0.234 | 91 |
| **E** `sd(J(pilot))` | **2.44** | **2.44** | **8.8** |

The ladder tops out at **β = 16**. Swapping the point set *inside the spec's formula* buys **1.28×**,
not 12× — the `J*` anchor dominates. **M6's "12×" is `32.5/2.44`: a ratio between an anchored *range*
and a *spread*, two different quantities.** The fix that works leaves the formula.

**`sampler.energy_scale = "pilot_sd"` (new, additive — `warmup_range` untouched).** The *identical*
ladder now closes **75.8%** of the gap at β=16 (E[J] −12.18 → **+4.24**, monotone, R̂ ≤ 1.06) where
`warmup_range` closed **13%**. Re-rounding (spec §17.4) lands beside it: cond(C_q) **1.54e4 → 5.97e3**
(2.57×), step_scale_ratio 0.0081 → 0.0129. Full reasoning: **BUILD_PLAN §1.6.6**.

> ⚠️ **The cond figures above were corrected in M10.2b, and the correction is a finding.** They read
> 5.36e3 / 2.87× / 0.0137 until then — numbers measured in **M10.1, before M10.2a removed the pilots'
> `optimum_coordinates` start hint**. That removal *changes every pilot's draws* — M10.2a's own
> `CALIBRATION_IMPL_VERSION = 2` note says so, in order to justify a cache-invalidating bump — and
> `cond(C_q)` is a function of those draws. Nobody re-measured. Confirmed by re-running the old path:
> **with the hint 5304, without it 5969.** The finding survives, its magnitude was stale. See
> **BUILD_PLAN §1.6.6b**: *a recorded measurement is a claim with a premise, and it expires silently
> when the premise moves.*

**What may now be said, and what may not.** β is the **local** Fisher-standardized coordinate —
`I₀ = 1`, `KL(π_β‖π_0) = ½β² + O(β³)` — and that is **exact at the *estimand* level only**: the
implemented coordinate uses the frozen plug-in, so `I₀ = σ₀²/σ̂₀²`. It is **not** a universal finite-β
axis, **not** Fisher–Rao arc length at finite β, and it does **not** make the ladder "span". That is
M6's own "engine validated, scale not calibrated" distinction, one layer deeper — and I was about to
write the overclaim into the docs until `/collab` caught it.

**No scalar is universal, so σ₀ sets the axis and Δ₀ is *reported*.** Codex's refutation of my
sharpest argument is the best thing in the exchange: if the neutral deficit `X = J* − J` has a density
of states `g(x) ~ C·x^{r−1}`, the tilted law is `e^{−κx}·g(x)` — **measure-zero is precisely what
*produces* the `x^{r−1}` power**, so `1 − q(κ) ~ r/(κΔ₀)` and the anchored coordinate *does* govern
gap closure in the sharp regime. Entropy **modifies** the coordinate; it does not defeat it. So a run
reports `Δ₀`, `G = Δ₀/σ̂₀` (**9.03** — the strain's headroom in neutral SDs), `β·G` and `q(β)`: the
anchored view stays a **derived observable** instead of being baked into the x-axis, where it would
hide the very cross-strain quantity §1.1 exists to compare.

### 🔴 Settled by M10: `r_eff` plateaus at ≈37 — and above β=64 the ladder measures its own mixing

Codex handed over a falsifiable prediction and it earned its keep. For piecewise-linear `J` near an
optimal face of dimension `f`, `r_eff(κ) := κ·[J* − E_κ J] → c = d − f`, with `κ²·Var_κ(J)` → the same
`c`. **The small-κ expansion `r_eff = κΔ₀ − κ²σ₀² + O(κ³)` is confirmed to three digits** (κ=0.104:
predicted 2.20, measured **2.182**; κ=0.209: predicted 4.27, measured **4.263**) — a formula derived
on paper by an independent model, landing on this sampler's output.

Measured plateau: 35.4 (β=16) → **37.4 ± 1.9 (β=32) → 37.0 ± 3.6 (β=64)**, flat within MCSE, with the
corroborator agreeing where it should (`κ²Var = 38.6` at β=32). So **c ≈ 37–39 ⇒ the optimal face has
dimension f ≈ 7–9** in a d=46 polytope. Tentative and under-powered — but two instruments sharing no
formula agree.

**Above β=64 the numbers measure mixing failure, not geometry**: R̂ climbs 1.22 → 1.39 → 1.79 →
**1.91** and ESS collapses to **4**. The proof it is not physics is M6's own theorem — `dE_β[J]/dβ =
Var_β(J)/s_J ≥ 0`, yet E[J] **falls** 8.6357 → 8.6109 from β=128 to β=256. *A drop is never physics.*
Codex's `J*`-indictment signature (linear drift: `r_eff` 44 → 91 as κ doubles) duly fires there and is
**unattributable**, because the diagnostic's precondition is a converged chain. **Practical rule:
under `pilot_sd`, β = 16 is the working top rung at 4×(2000+2000)**; β ≥ 32 needs a far longer
schedule, because a tilted chain concentrates and its chords shorten.

### ⚠️ Settled by M10: the RNG stage was hardcoded, so the two pilots drew **identical numbers**

`run_chain` keyed its stream on `(model_id, **"sample"**, β_index, chain_index)` — a literal. The
geometry pilot and the scale pilot are β=0 chains on the same model with the same chain indices, so
the *stage* is the only coordinate that could separate them: they drew the **same draws**, and the
independence that makes pilot-seed sensitivity attributable was a comment rather than a fact.
`run_chain`/`run_chains` now take `stage` (default `SAMPLE_STAGE`; production never passes anything
else). **Found by `test_the_two_pilot_stages_draw_different_numbers` failing on its first run** — the
test was written from Codex's design argument, before the code existed to violate it.

> **M9 was not math-critical** — but it *became* so mid-milestone: the benchmark's own worker sweep
> could not run, because M5's mass-balance gate rejects a valid genome-scale geometry ~33% of the
> time. Fixing it required a `/collab` review (2 rounds, converged) and it killed my first fix. See
> **BUILD_PLAN §1.4.2**. The lesson generalizes: *a milestone that only measures can still discover
> that something it measures is wrong.*

### ✅ Settled by M7: reweighting is a **feasibility-checked heuristic** whose weights are frozen — and λ must move with them

`reweighting.reweight_objective` runs spec §13's loop (`w_r ← w_base/(|v_r|+ε)`, clip,
median-renormalize) to a **weight fixed point**, then freezes. It is **experimental** and does not
claim exact cardinality — the manifest says so. On the example model at λ̃ = 0.25 it sheds 134 → 131
active reactions; the frozen objective flows through the whole sampler with **zero HiGHS solves after
the freeze** and every tilted sample feasible in the full 773-reaction polytope.

**The M3 fork is settled by measurement: λ is re-resolved every iteration (`λ_k = λ̃·λ*(w_k)`).** `λ*`
is a function of `w`, and one reweighting step moves it 1.9e-3 → ~4e2 (default clip) because `C_w`
changes *units* (a sum of fluxes → nearly a count of active reactions). A **frozen** λ collapses the
effective pressure `λ/λ*(w)` from 0.5 to ~4e-6 **and crashes M3's `z == |v|` gate by iteration 2**
(deviation 25). Re-resolving keeps `λ̃` meaning the same selection pressure across the loop and the
batch, and makes the median renormalization a mathematical **no-op** (`λw` is invariant to `w → cw`).

**Two silent-degeneration traps, both now reported rather than hidden:**
- **A too-tight clip ceiling turns reweighting back into plain L1** — it merges "nearly off"
  (`|v| ≈ 1e-3`) with "off". Measured: clip [1e-2, 1e2] sheds 0, [1e-3, 1e3] sheds 3. The report
  carries `n_turned_off`, `n_turned_on` and `support_unchanged`; the warning fires on the symmetric
  difference being empty, not on net `n_shed == 0` (which a straight swap would trip spuriously).
- **Convergence is on the *weights*, not the fluxes.** A global relative `max|Δv|` is dominated by a
  large flux and blind to the small sparsity-critical one whose weight is still halving, so it could
  freeze weights one stale step short of the fixed point. The stop test is now a per-reaction relative
  **weight** change — the frozen artifact is the weights, so convergence must be about the weights.

**Every input to `s_J` is now keyed on both the objective and the polytope** (BUILD_PLAN §1.6.5). See
the M7 collab findings below.

### ⚠️ Settled by M7: the codebase's signature bug, one level up — *two objectives on one polytope*

The `/collab` review ran **5 rounds** (converged AGREE) and its through-line is the M6 disease with
fresh fuel: **M7 is the first milestone with two objectives on one polytope** (base and reweighted),
and on the toy their `s_J` differ **100×** (0.68 vs 0.0068) while they share a `polytope_key` exactly.
M6's guard could not tell them apart. So `s_J = J* − Q_q(J(W))` — a subtraction of three
model-derived inputs — is now keyed on **both** the objective and the polytope at every one:

- `LPOptimum` gained a `polytope_key` (its `objective_key` hashes the objective's params, *not* the
  polytope's bounds, so two polytopes differing only in bounds hash identically — Codex round 2);
- `choose_energy_scale` requires a **`warmup_polytope_key`**, because the warm-up array is a bare
  `(K, n_free)` matrix a wrong-polytope set of the same shape would silently join (Codex round 3);
- the frozen weight buffers are **physically read-only**, and the reweighter **structurally cannot
  import the sampler**, so a weight can never move mid-chain.

`optimum_coordinates` is **deliberately not keyed**: it is a start *hint* that enters only the initial
state (never the kernel/objective/`s_J`), so a wrong one cannot change the invariant target — only
seed a poorer start, observable via feasibility and R̂/ESS. Codex conceded this (round 5); the boundary
is documented in `maxent_sampler.find_start` rather than papered over with a key that would imply it is
load-bearing.

### 🔴 Settled by M9: **a bar a valid input clears only 2 times in 3 is not a tolerance, it is a coin flip**

M5's rounding gate rejected a perfectly samplable genome-scale geometry on **8 of 24 RNG streams**,
and since `model_id` keys the RNG (`stream_seed` → span probes → support points → covariance → `L` →
`T`), **a *label* decided whether a model could be sampled at all.** The benchmark found it by
failing: the M9 worker sweep would not run.

**The signature that exposed it — worth recognizing again:**

| measure | median | max | spread | fails `span_tol=1e-9` |
|---|---|---|---|---|
| `‖S·T‖` **absolute** | 3.851e-12 | 5.535e-12 | **1.8×** | — |
| `‖S·T‖` **relative** (the gate) | 4.835e-10 | 3.038e-08 | **373×** | **8/24** |

**When a ratio is unstable and its numerator is not, the denominator is the thing that is wrong.**
The residual is an absolute floor inherited from the basis construction, not generated by the row's
own multiply — proved by a log-log fit of residual against row scale over 61009 (col,row) pairs:
**slope +0.165**, not the **+1** a locally-generated error requires. So the gate divided a fixed
~1e-13 by a per-row scale as small as 1e-5. **The M4 lesson — "never divide by a small number that is
noise" — one module further on.** M5's own reassurance ("3.5e-10 against a span_tol of 1e-9, it passes
on its own merits") was *one draw* from a distribution whose 79th percentile crosses the bar.

Also found: **the code never implemented its own documentation.** `rounding.py:156` documented a
per-column ratio of norms; `rounding.py:788` computed a max of per-(column,row) ratios. Five orders of
magnitude apart.

**The fix is a `certify_reachable_mass_balance`** — 2 LPs per metabolite bounding `max_i R_i` over the
reachable set `Y`, against the **same `η=1e-9` contract `diagnostics` already applies to emitted
samples**. Measured: **3.6e-11 … 5.1e-11, a 1.41× spread**, 20–28× inside the contract, 334 LPs / 0.5 s.
It lands just above M5's independently measured 2.6e-11 emitted-sample residual — as an upper bound on
a superset must. Full reasoning: BUILD_PLAN §1.4.2.

### ⚠️ Settled by M9: I walked into the trap M4 wrote down, and `/collab` caught both

Two of M9's own defects were failures to heed this repo's recorded lessons:

- **My proposed fix was unsound.** Codex's counterexample: `S=[[1,-1,0],[0,0,1]]`, `|v₁|,|v₂| ≤ 1e12`,
  `|v₃| ≤ 1`, `T_k=(1,1,1e-10)`. The per-column formula reports `1e-10/2 = 5e-11` and **passes** —
  while `v₃`'s bound lets the chord reach `|y| ~ 1e10`, so `v₃` hits **1.0**: a mass-balance violation
  of order 1 with every reaction bound satisfied. Dividing by the *largest* row scale lets unrelated
  huge reactions hide a 100%-relative violation. **Withdrawn.**
- **I certified from a primal reading.** M4 recorded: *"Never certify flatness from a primal reading;
  M5/M6 will face the same temptation."* A returned `objective_value` is a **lower** bound on a max, so
  a solve stopping short reports the reachable residual too *small* — unsound in the dangerous
  direction. The bound is now weak-duality, valid for **any** multipliers.

**And a solver fact worth keeping**: HiGHS **drops a 1e-10 matrix coefficient** sitting beside 1.0
coefficients — it reports that row's activity as **0.0** where the truth is **133.3**, with
`max_primal_infeasibility = 0.0` and status optimal. Every tiny objective must be **normalized before
it reaches the solver**; `E_i ≈ 1e-13` raw sits under the dual feasibility tolerance and every reduced
cost reads as zero.

### ✅ Settled by M9: the β>0 line kernel *is* the sampler's cost — and the sort is not the reason

A β>0 coordinate update costs ~104 µs; **`sample_line` is 89% of it** and `build_piecewise_j` alone is
**55%**. β>0 costs **7.98×** a β=0 sweep. But BUILD_PLAN's hypothesis ("breakpoint-sort profiling")
was wrong: the chords carry a **median of 2 interior breakpoints (max 8)**, so `np.unique` is paying
fixed NumPy call overhead (~12 µs), not sorting. **You cannot optimize a sort of 2 elements.**

What is actually there: **`validate()` (11.8 µs) + `baseline` (6.5 µs) = ~18% of every β>0 update is
work the draw never reads** — `baseline` is an absolute `J`, which M2 proved cancels out of `p(t)`
exactly. Left alone in M9 on purpose (measure-and-assert; `line_distribution` is the M2 math-critical
kernel). It is the measured lever for M10 if β>0 wall-clock binds.

### ✅ Settled by M9: execution mode does not touch the numbers — confirmed by a second instrument

The worker sweep found **ESS(J) identical to the last digit at 1, 2, 4, 7 and 14 workers** (spread
exactly 0). M8 asserted byte-identical fluxes; this is the same claim seen through a statistic that
was not built to check it. Throughput: **14.77 ESS/wall-s at 14 workers** (7.76× speedup, 55%
efficiency). The efficiency decay is **Amdahl, not contention** — the parent's serial per-model
prepare is 4.0% of the run (ceiling 24.9×), and measured tracks predicted to 98/95/88/84%. **The lever
on the ceiling is M8's L3 cache**, since `geometry` is 1.17 s of the 2.29 s serial.

### ✅ Settled by M8: the L0 key is now **content-addressed** (the open defect is fixed)

`build_canonical_model` no longer hashes `source_path` for identity. The L0 key is a fingerprint of
the IR the model *actually holds* (`model_id`, the polytope's `content_key`, the exchange mask, folded
with the cobra + parser versions), so a model mutated in memory — or paired with the wrong
`source_path` — gets a *distinct* key instead of inheriting an unrelated file's identity. The file's
`sha256` is still recorded as provenance on the trusted `load_canonical_model` path (which both hashes
and parses one file), but it is never the identity. M8's cache computes a separate file-lookup key to
skip re-parsing across runs, and validates every loaded array's content hash. See BUILD_PLAN §1.1.

### ✅ Settled by M8: the cache is a **layer-generic content-addressed store**; geometry is wired to it

`cache.ArtifactCache` stores `{name: ndarray}` bundles under any caller-supplied key, with an atomic
`mkdir` **writer claim** (one writer per key; losers wait for `COMPLETE`, then load), all-or-nothing
publication, and a stored sha256 per array recomputed on load. It is **domain-free and solver-free**,
so a `spawn`-ed worker can import it. Of the four-layer DAG, the **expensive, β-independent geometry
(L3)** is wired through it (`RoundedTransform.to_bundle`/`from_bundle`, which rebuild the precompute
from `T` and refuse a wrong-polytope reconstruction); L0/L1/L2 are recomputed per run because they are
cheap (parse + reduce + a handful of LPs), and per-`(β, chain)` **samples** live in the results tree
with their own `COMPLETE` markers — which is what makes restart per-unit. Wiring L2 to the same store
is a mechanical extension, deferred while it recomputes in milliseconds.

### ✅ Settled by M8: execution mode does not touch the numbers

Serial (`n_workers=1`, in-process) and the `spawn` process pool produce **byte-identical fluxes**,
because every chain's RNG is keyed on `(model_id, "sample", β_index, chain_index)` — never on a
position in a dispatch queue. A worker imports `maxent_sampler`/`output`/`rounding` and **never cobra
or HiGHS** (verified at import); the parent does all parsing and LP work and ships frozen arrays. BLAS
threads are pinned to 1 via env set before the pool spawns, so the fresh NumPy in each worker inherits
it (the real oversubscription risk in solver-free workers).

### 🔴 Settled by M6: the engine is validated, the **β-scale is not calibrated** — and M10 is now a prerequisite

**M6 ships a maximum-entropy *engine* whose tilt is exact and whose *magnitude* is pinned — with a β
axis that does not yet mean what a reader would assume.** The distinction was forced by measurement,
and BUILD_PLAN §2.1 now records it.

`s_J = J* − Q₀.₀₅(J(W))` (spec §22.2) is taken over M4's **support-LP vertices** — extreme points,
where the L1 cost is enormous and `J` runs down to −28. The chain lives in the *interior*, at
`J ≈ −12` with `sd(J) = 2.6`. So **`s_J = 31.3` is calibrated to a range 12× wider than the one the
sampler explores**, the linear response `dE_β[J]/dβ = Var_β(J)/s_J` is only 0.22 per unit β, and:

| β | E[J] | MC se | ESS(J) | R̂(J) |
|---|---|---|---|---|
| 0 | −12.07 | 0.31 | 69 | 1.03 |
| 4 | −11.12 | 0.26 | 91 | 1.05 |
| 16 | **−8.93** | 0.33 | 65 | 1.07 |

Monotone (every rung rises by ≥ 2.3σ), total rise **3.14 = 6.9σ** — against a linear-response
prediction of 3.44, the shortfall being `Var` shrinking, exactly as it should. **The sampler is right.
The ladder is weak**: β = 16, the *top* of spec §22.1's own ladder, closes only 13% of the gap to
`J* = 9.47`.

The remedy is named in spec §22.2 itself ("support **or pilot** points") and already deferred to
**M10**: read `s_J` off a β=0 pilot chain's own `J` spread (2.6) and the identical ladder tilts ~12×
harder. It changes *what β names*, not the target at any given β — the distribution M6 validates is
untouched. **So M10's pilot-based `s_J` is now a prerequisite for presenting the ladder as spanning
neutral-to-strongly-selected regimes.** Until then a run reports what it measured and claims nothing
more.

### ⚠️ Settled by M6: this codebase's characteristic bug is **two artifacts that never met**

The `/collab` review ran **6 rounds** and found **twelve defects**, and by round 5 they were visibly
one bug wearing twelve hats:

> **Two artifacts that were never computed against each other, being silently joined.**

A `ReducedObjective` is indices and weights; a `ReducedPolytope` is a matrix and bounds. Neither knows
the other exists, and *an index is just an integer*. So a mismatched pair is not **detectable**
downstream — it is **computable**, and it computes confidently: the chain tilts by whatever reactions
the objective names, `evaluate_many` reports *those same reactions* as `μ` and `C`, and the trace of
`J` **rises monotonically with β exactly as the theorem demands** — because the chain really is
maximizing the thing the trace is measuring. Feasibility, mass balance, the chords and R̂ all stay
green. **Nothing in this package knows which reaction `J` is supposed to be about.**

Each round Codex named one more unguarded join and each time I patched *that join*. That was the
mistake. **The fix is an invariant, not a patch**: `ReducedPolytope.content_key()` is the L1 identity
(and it hashes `biomass_full_index` — the reaction, not its reduced *coordinate*, which is `None` for
every fixed-biomass model and therefore collapses them all together); every downstream artifact
carries it; and `sparse_objective.check_compatible` is called from **every** public join, where it was
previously called from none.

**Bound now**: `lower_objective`, `build_sparse_objective_lp`, `biomass_maximum`,
`critical_l1_penalty`, `solve_sparse_objective`, `resolve_objective` (canonical↔reduced),
`build_transform` (geometry↔polytope), `run_chain`, `run_ladder` (transform↔polytope↔objective↔`s_J`).

**Deliberately NOT bound — the inner loop keeps its invariant by construction.** `chord_on_support`,
`build_piecewise_j` and `sample_line` run 46 × 12000 × 4 × 3 times and BUILD_PLAN §1.3 forbids
per-step overhead there. Their invariant is enforced once, in the right place: M5 *removed* a
caller-supplied `support` from `feasible_chord` precisely because an unvalidated one reintroduced the
§1.6.1 bug, and `CoordinatePrecompute.build` now **derives** the support from `T` and validates it
against the column.

### ⚠️ Settled by M5: the sampler is correct but this model MIXES SLOWLY — plan the schedule for it

`step_scale_ratio = 0.008`: the shortest rounded axis is 125× shorter than the longest, so coordinate
hit-and-run crawls along it. Measured on the example model, **4 chains × (N burn-in + N sampling)
sweeps**:

| sweeps | max R̂ | min ESS | median ESS | of |
|---|---|---|---|---|
| 500 + 500 | 1.32 | 6 | 29 | 2000 |
| 2000 + 2000 | 1.08 | 26 | 119 | 8000 |
| 3000 + 3000 | 1.08 | 34 | 154 | 12000 |
| 8000 + 8000 | 1.04 | 251 | 397 | 32000 |

ESS grows about linearly and R̂ falls monotonically — the signature of a correct-but-slow chain, not a
stuck one (no coordinate has zero within-chain variance at any length). **The `SamplerConfig` defaults
(1000/1000) are not enough for this model to reach R̂ < 1.01.** Report R̂/ESS with every run and set the
schedule from them, rather than trusting a default.

**The known remedy is spec §17.4 pilot rounding, and it is measured, not hypothetical.** Re-rounding
from the covariance of an actual β=0 pilot chain (instead of the support-LP vertices, which are only
an initial approximation) improves `cond(C)` from 1.56e4 → 5.14e3 and **ESS by ~2.5×** (median
174 → 428 at 3000+3000). It is deferred to **M10** by BUILD_PLAN, deliberately — it is a separate DAG
stage, not a change to the target. If M6/M8 wall-clock becomes the binding constraint, this is the
lever to pull, and it does not touch the validated distribution.

### ✅ Settled by M5: rounding cannot move the target — and `diag(s)` and `L` do different jobs

`range(T) = range(diag(s)·B·L) = range(diag(s)·B)` exactly for **any** invertible `L`, so the ridge is
a free engineering parameter and *transform-invariance is a testable claim*. It is tested: two
transforms whose ridges differ by seven orders of magnitude sample the same flux distribution, checked
in units of **Monte-Carlo standard error** (max |z| < 5, mean z² < 2 over 199 reactions) rather than in
units of σ — the naive "means agree to 0.25 σ" bar failed at 0.39 σ on two runs that are perfectly
consistent, because at ESS ≈ 1% the standard error of a mean is already ~0.1 σ.

**Scaling and rounding are not the same job.** `diag(s)` fixes the axes' *units*: an axis-aligned
1000:1 stretch is absorbed before rounding is reached (measured — the unrounded chords differ by 1.41,
not 1000). `L` fixes their *correlations*, which no diagonal matrix can see. That is where the 41×
improvement in the worst chord comes from.

### ✅ Settled by M4: the sampling dimension is 46, not 55 — and the geometry hands M5 a usable start

**61 of the 260 free reactions cannot carry flux at all.** The model file leaves `l < u`, but mass
balance pins them, so `n_free − rank(S) = 55` is only an *upper bound* and the true affine dimension
is **d = 46** (confirmed by an independent FVA+rank oracle sharing no code with the geometry).

That is not bookkeeping. A blocked reaction is an *exact structural zero* of the direction space, and
a basis row of ~1e-15 there — divided by a centre sitting ~1e-13 outside its own bound, both pure
solver noise — produces **a chord limit of order 0.03–0.5**, right inside the legitimate chord. The
measured chord at the centre was `[−0.54, −0.39]`, which **excludes `t = 0`**; `line_geometry` refused
it, so **M5 could not have started from that centre.** Blocked components are now projected out
exactly. See BUILD_PLAN §1.4.1.

**What M5 inherits, already checked:** every basis direction's chord through the centre contains
`t = 0` with positive length (min 0.018); the centre is *exactly* bound-feasible; and the support
points span all 46 directions (rank 46/46) — so M5's covariance ridge cannot quietly conceal a
singular covariance instead of failing on it.

### ⚠️ What the span certificate does and does not claim (M4 collab, 6 rounds)

It licenses exactly this: **every feasible direction of the exact polytope has its component
orthogonal to `range(B)` bounded in width by `SpanCertificate.resolution`** (2.78e-11 scaled = 5.6e-8
flux units on the example model). It is **not** "cannot under-count a dimension" — a direction thinner
than the resolution can be missed, and `blocked_tol` drops one narrower than itself.

The asymmetry runs the *safe* way: the geometry may **over**-count (admit an ε-feasible direction) but
cannot omit a direction it had the resolving power to see. Over-counting is benign for a sampler — the
chain explores a slightly larger set, and every sample is still checked. Omitting a wide direction
would silently delete part of the support, and no downstream test would ever see the samples that
were never drawn.

### ✅ Settled by M3: λ is scale-referenced (`λ = λ̃ · λ*`)

`J = μ − λC` compares a biomass flux with a sum of hundreds of absolute fluxes; above a
model-specific `λ* = max_v μ(v)/C(v)` the LP optimum is **exactly the origin** and the cell stops
growing. The old default `λ = 1.0` was **529× past that cliff** on the example model. So the config
now takes a **dimensionless `λ̃`** (`objective.l1_penalty_scaled`, default 0.5) and `resolve_objective`
computes `λ = λ̃ · λ*` per model — `λ*` exactly, from one Charnes–Cooper LP. `λ̃ = 0` is plain FBA;
`λ̃ → 1` is maximum sparsity pressure that still grows; `λ̃ ≥ 1` is refused when the origin is
feasible. **Same `λ̃` = same selection pressure in every strain**, which is what the cross-model
comparison needs. Full reasoning: BUILD_PLAN §1.7. **M7 must still decide** whether λ stays frozen at
its base-weight value through the reweighting loop or is re-resolved from the frozen final weights
(`λ*` depends on `w`).

### Platform facts established by M0 (build on these, don't re-derive)

- Python **3.11.15**, aarch64/Jetson. Wheel-only install verified with `uv pip install -e ".[dev]" --only-binary=:all:` — **no source builds**. Pinned in `uv.lock` (47 packages).
- Resolved versions: **cobra 0.31.1 · highspy 1.15.1 · numpy 2.4.6**.
- **SciPy is absent from the venv entirely** — stronger than the gate required (§4 anticipated cobra might pull it transitively; it does not). The no-scipy gate is enforced by `tests/unit/test_no_scipy.py` at both runtime and source level.
- HiGHS accepts native `int32` CSC index/start arrays + `float64` values via `passModel`. The biomass LP matches cobra's own FBA optimum to `rel=1e-6` — the CSC assembly is verified, not merely accepted.
- ⚠️ **highspy attribute reads return Python `list`, not NumPy views** (the pybind layer copies). M3's LP layer must keep its own float64 arrays and extract solutions in one `np.asarray` shot — never element-wise. Pinned by `test_highspy_returns_python_lists_not_arrays`.

### Facts established by M5 (the sampler — build on these, don't re-derive)

- **The β>0 plumbing is already in place and *refuses* to run half-configured.** `run_chain` takes
  `beta`, `objective` and `energy_scale` and passes them straight to M2's `sample_line`; it raises if
  `β > 0` arrives without an objective or with a non-positive `s_J`. M6 supplies the `L1Objective` in
  **reduced** coordinates (not full — the sampler's `v` is length `n_free`), `s_J`, the ladder and the
  traces. It does not need to touch the transition kernel.
- **Time is measured in *sweeps*, one sweep = `d` coordinate updates.** `burn_in`, `n_samples`, `thin`
  and `refresh_interval` are all in sweeps, so a schedule means the same thing across a batch of
  models with different `d`. Counting single updates would make `burn_in = 1000` mean 21 passes here
  and 1000 on a 1-D model.
- **A relative residual needs a *floor* as well as a denominator.** `NativeCSC.relative_residual`
  divides by `max(|S|·|v|, 1.0)`. The floor is not slack: 24 metabolite rows of this model are touched
  by a **single** free reaction, where `residual = |S_ij·v_j|` and `scale = |S_ij|·|v_j|` are *the same
  number*, so an unfloored ratio is identically 1.0 for any nonzero flux. One such row (`cpd02375_c0`,
  both its reactions FVA-blocked) made the sampler report a relative mass-balance error of **1.0** from
  an absolute one of 3.4e-14. **But the floor must not touch a *direction*:** `T`'s blocked rows are
  exactly `0.0`, so there is no noise to divide by, and flooring the transform's own check would only
  weaken it (measurably — on 2049 of 41124 rows). Correct where the noise exists, absent where it can't.
- **`np.min(x, initial=0.0)` is not an empty-array guard.** For a *min* reduction `initial` is a
  candidate, so it floors the answer at 0 — `ConvergenceReport.min_ess` reported an ESS of **0** for a
  sample whose every entry was 8000. Same trap in the mirror direction for `np.max(..., initial=1.0)`.
- **`@dataclass(frozen=True)` freezes the binding, not the buffer.** And `np.ascontiguousarray` returns
  its argument *unchanged* when it is already contiguous and float64 — so freezing an array in place
  can reach back through an alias and freeze the caller's object underneath it. `rounding` copies
  before it freezes.
- **A missing dimension produces no bad numbers, only absent ones.** Nothing in a feasibility check,
  a chord, or a mass-balance residual can see a `T` that has silently lost a column — the chain just
  samples a lower-dimensional slice of the polytope, perfectly cleanly. Hence the explicit SVD rank
  check. M6 and M7 should assume the same about anything they add: *the dangerous failure is the one
  that removes states, not the one that produces wrong ones.*

### Facts established by M4 (the geometry — build on these, don't re-derive)

- **`d = 46`, and the certificate cost 1089 LPs / 1.2 s.** FVA is 520 of them, discovery 140, the
  complement sweep 428. Warm-started simplex; ~4800 total pivots. Cheap enough to leave alone.
- **A width has two ends and needs two instruments.** The *primal* width (objective difference of two
  returned endpoints) is a **lower** bound: it proves a direction exists. Certifying a direction
  *flat* needs an **upper** bound, and only weak duality gives one that assumes nothing about the
  solver — not optimality, not even primal feasibility. Never certify flatness from a primal reading;
  M5/M6 will face the same temptation with `s_J` and the energy traces.
- **A mass-balance residual must be judged on a *relative* bar.** `S·v` sums terms of size ~1e5 here,
  so evaluating it costs ~1e-10 of rounding before any solver error. An absolute 1e-9 bar charges that
  to the solver and fails a perfectly good geometry (measured). `NativeCSC.cancellation_scale`
  (`|S|·|x|`) gives the scale to divide by — and it *cannot* be had from `matvec(abs(x))`, which
  re-applies the signed `S` and cancels all over again.
- **Never divide by a small number that is noise.** Two of M4's bugs were the same shape: a ~1e-15
  basis row divided into a ~1e-13 bound violation gave a chord limit of 0.03–0.5, and a Gram-Schmidt
  residual of ~1e-3 divided into a 1e-12 LP row residual gave a basis error of 8e-10. Both were
  measured, neither was visible in any test that passed.
- **`stream_seed(model_id, stage, β_index, chain_index)`** (in `provenance`) is the RNG keying M5's
  chains must use. It hashes with sha256, **not** Python's `hash()`, which is salted per interpreter —
  a spawn key built from that would name a different stream in every worker.

### Facts established by M3 (the LP layer — build on these)

- **`HighsLinearProgram` is the only place that touches `highspy`**, and it imports it *inside* the
  constructor. So `sparse_objective` can be imported by an MCMC worker without loading a solver
  (§1.2's "a worker never imports HiGHS"). Pinned by a subprocess test.
- **HiGHS adds `lp.offset_` to the reported objective with its sign intact under `kMaximize`**
  (probed, then pinned). That is how the fixed reactions' contribution to `J` — which no LP variable
  can express — reaches the solver's objective, making "solver objective == directly recomputed J"
  one *complete* equation rather than one missing a constant.
- **A `z` column exists only where `λ·w_r > 0`.** A zero-cost `z` has nothing pushing it down onto
  `|v_r|`; it would settle anywhere in `[|v_r|, z_max]` and fail its own `z == |v|` check on a
  solution that is perfectly correct in `v`. So `λ = 0` builds no auxiliaries at all and the LP
  collapses to the flux-only model — which is also the right answer.
- **Solve counting is process-global, and programs can be `freeze()`d.** Per-instance counts would
  let a sampler evade the "no solver in the inner loop" assertion by building a fresh LP. M5's gate
  can now assert *and* prohibit.
- **Warm starts pay off at genome scale**: 50 random objectives on the §14 flux LP re-solve in well
  under the cold-start pivot count. The sequential geometry phase (§1.2) is on solid ground.
- **λ is scale-referenced, and `λ*` is exact.** `critical_l1_penalty` gets `λ* = max_v μ(v)/C(v)` from
  **one** LP — `max μ/C` is linear-fractional, and Charnes–Cooper (`y = v·t, t = 1/C(v)`) turns it
  into "maximize μ(y) subject to a unit cost budget". Don't bisect it. `resolve_objective` is the
  config-driven entry point; `SparseFluxObjective.from_polytope` stays pure and takes a **raw** λ.
- ⚠️ **`λ*` depends on the weights** (doubling `w` halves `λ*`). M7 must decide whether λ stays frozen
  at its base-weight value or is re-resolved from the frozen final weights — it moves `J` either way.

### Facts established by M2 (the line kernel is now a trusted oracle — build on it)

- **The line kernel takes no `J*`.** It cancels out of `p(t)`, and carrying it invites catastrophic
  cancellation. M6 will still need `s_J` and `J*` for *diagnostics* (energy traces), but must not feed
  `J*` into the draw.
- **M5 must NOT redraw a coordinate when a chord is degenerate** — that makes coordinate selection
  state-dependent and breaks stationarity. `sample_line` already returns the correct self-loop; just
  apply it (`y_k += 0`). See BUILD_PLAN §1.6 delta 6.
- **M5 builds the per-coordinate precompute itself.** An unvalidated caller-supplied `support` array was
  removed from `feasible_chord`: a truncated one silently reintroduces the §1.6.1 tolerance bug. The
  precompute must be *derived* from `T`, so the invariant holds by construction.
- **`PiecewiseLinearJ.values`/`evaluate()` return absolute `J` and are for reporting only.** Never form a
  probability from them; the mass path uses `heights` (peak-relative) exclusively.
- Weights, `λ`, `β` and `s_J` are frozen inputs to the kernel. M7's reweighting must complete *before*
  sampling starts — a weight that moves mid-chain retargets every conditional and destroys stationarity.

### Facts established by M1

- **CSC index width is `int32`, not the spec's `int64`.** `highspy.kHighsIInf == 2**31 - 1`, i.e. HiGHS is built with a 32-bit `HighsInt`; int64 arrays are *accepted* but silently narrowed on every `passModel`. `native_csc.INDEX_DTYPE = np.int32`, and the 2³¹ nnz ceiling is a construction-time check. Pinned by `test_highs_index_width_is_what_native_csc_stores`.
- **cobra rejects NaN bounds, inverted bounds and duplicate IDs itself** — but happily accepts **infinite** bounds, which we must reject (an unbounded polytope has nothing to sample). Our own guards still matter for models built/mutated in memory rather than parsed.
- **New module `provenance.py`** (not in spec §6): L0/L1 content keys were needed long before M8's cache exists, and the core must hash arrays without importing cobra.
- The toy network (`examples/toy_network.json`) exists to supply the case the example model **cannot**: a reaction fixed at a **nonzero** value (`FIX = 2.0`), making the reduced mass balance genuinely affine. All 513 of the example model's fixed reactions sit at zero, so it would never catch a homogeneous-RHS bug.

## Verify current state

> ✅ **M10.2e (2026-07-17): the workaround is gone, and it is the *absence* that is the milestone.**
> These commands are now written without an `OMP_NUM_THREADS` pin, and they pass **from a clean
> state** under whatever threading the shell happens to have. Until M10.2e they did not, and every
> recorded verification here — mine included — quietly reused a cache warmed by a threads-pinned
> probe. **Run the pilot-DAG command below against a `--cache-dir` you have just deleted**; that is
> the check that was never actually being run.
>
> ```bash
> # Was the M10.2e blocker; now completes (1/1 units). Worth keeping as a smoke test, because it is
> # the exact command that failed for ten milestones while everything else looked green.
> M=models/GCF_000010425_1_ASM1042v1_protein_non_gapfilled_latest_gapfilled_noO2.json
> rm -rf /tmp/thr && env OMP_NUM_THREADS= .venv/bin/gsmm-compiler maxent sample $M \
>   --out /tmp/thr/out --cache-dir /tmp/thr/cache --set sampler.energy_scale=pilot_sd \
>   --set sampler.pilot_reround=true --set sampler.betas=[0.0] \
>   --set sampler.n_samples=50 --set sampler.burn_in=50
> ```

✅ **The suite and the CLI are both green from a clean state, at any thread count** — which is the
milestone. Measured, deterministic (not flaky — repeated runs agree):

| | `pytest` (979) | `maxent sample`, clean cache |
|---|---|---|
| **ambient threads** | ✅ 979 passed | ✅ completes |
| **`OMP_NUM_THREADS=1`** | ✅ 979 passed | ✅ completes |

The R̂ test that used to straddle its bar (`test_the_chains_mix_and_the_diagnostics_say_so`) was
settled by its **schedule**, not by the pin: the bar was inside the distribution of valid runs across
*seeds*, so threading was never the cause. See the M10.2e section above.

```bash
cd /home/mcpu/GitHub/gsmm_compiler_maxent_sampling
.venv/bin/python -V                                    # expect 3.11.15
# The thread count no longer changes any of this (M10.2e). Both of these pass under ambient
# threads and under OMP_NUM_THREADS=1 — that equivalence IS the milestone, so check it if in doubt.
# Note `pytest -q | tail` reports *tail's* exit code, which is always 0: read the count, not $?.
.venv/bin/python -m pytest -q | tail -3                # expect 979 passed
.venv/bin/python -m pytest -q -m "not slow" | tail -3  # the fast subset
.venv/bin/ruff check . && .venv/bin/mypy               # expect clean
.venv/bin/gsmm-compiler model inspect examples/toy_network.json     # affine RHS: nonzero
M=models/GCF_000010425_1_ASM1042v1_protein_non_gapfilled_latest_gapfilled_noO2.json
.venv/bin/gsmm-compiler model inspect $M
.venv/bin/gsmm-compiler maxent build-geometry $M       # d=46; reachable ‖Sv−b‖ CERTIFIED ~3.8e-11
.venv/bin/gsmm-compiler maxent benchmark $M --repeats 1 --sweeps 100   # regenerate the M9 report

# M10.2a/b/d: the pilot DAG from the CLI, with L0 + geometry + pilots all cached.
# Expect "re-rounded: cond(C_q) 1.54e+04 → 5.97e+03 (2.57×); T₁ reachable ‖Sv−b‖ 3.87e-11
# (certified, 26× inside contract)" and 4/4 units. Since M10.2e this needs NO thread pin — and
# those cond figures are now the *only* ones it can print, which is the point of the milestone.
.venv/bin/gsmm-compiler maxent sample $M --out /tmp/m102 --cache-dir /tmp/m102/cache --workers 2 \
  --set sampler.energy_scale=pilot_sd --set sampler.pilot_reround=true \
  --set sampler.pilot_chains=2 --set sampler.pilot_burn_in=300 --set sampler.pilot_samples=300 \
  --set sampler.betas=[0.0,16.0] --set sampler.n_chains=2 \
  --set sampler.burn_in=300 --set sampler.n_samples=300
# Re-run it verbatim → resumes (4/4, ~4 s). Re-run with --set sampler.n_samples=400 → REFUSES
# ("marked COMPLETE but was sampled by a different recipe"), which is the §1.1 restart guard.

# M10.2b/d: the cache is the milestone. Re-run against a WARM --cache-dir and watch
# `prepare_model` fall 22.9 s → 0.645 s (35×) with T₁ and s_J bit-identical:
#   "geometry_pilot: loaded from cache (…)"  — not "running 4 chains × …"
# and no "parsing … (cobra; not cached)" line at all — a warm run never imports cobra.

# M11 (the real batch): build-geometry across all 40 curated strains. Expect 40 OK after M11.3.
# The 6 kUnknown@reachable_mass_balance failures are fixed durably; the 4 formerly-deferred
# (2 Hafnia, pumilus, Liquorilactobacillus) pass here as basis-marginal (may flip on another basis).
# This is the measurement that drives M11; re-run it after each M11 milestone to see the count move.
D=/home/mcpu/GitHub/metabolicSubcommunities/models/gapfilled/method_3_curated
for f in "$D"/*.json; do
  out=$(.venv/bin/gsmm-compiler maxent build-geometry "$f" 2>&1)
  if echo "$out" | grep -q "dimension"; then echo "OK   $(basename "$f" | cut -c1-40)"
  else echo "FAIL $(echo "$out" | grep -oiE 'kUnknown@[a-z_]+|cannot be resolved|does not resolve' | head -1) $(basename "$f" | cut -c1-40)"; fi
done
```

---

## Milestone checklist  (v1 = M0–M9 · M10 deferred)

Legend: ⬜ todo · 🟨 in progress · ✅ done (gate passed)

### ✅ M0 — Platform & packaging spike  *(gate passed 2026-07-13)*
Gate: wheel-only install on Python 3.11/aarch64 · example model LP solves · core imports no scipy.
- [x] `pyproject.toml` — src layout, `requires-python==3.11.*`, deps cobra/highspy/numpy; dev: pytest, pytest-cov, ruff, mypy; `gsmm-compiler` console script
- [x] package skeleton `src/gsmm_compiler/` with module stubs (per BUILD_PLAN §6 / spec §6) + `__init__.py` + `py.typed`
- [x] `uv venv` on Python 3.11 + `uv pip install -e .`; `uv.lock` pinned, **no source builds** (`--only-binary=:all:`)
- [x] smoke: load Bifido model with cobra + build one native-array `highspy` LP via `passModel` + solve — **and cross-check the optimum against cobra's own FBA**
- [x] no-scipy scan: assert the numerical core modules import zero scipy (runtime + static AST scan)
- [x] `gsmm-compiler model inspect models/GCF_000010425_1_..._noO2.json` prints basic report

### ✅ M1 — Canonical + reduced model IR  *(gate passed 2026-07-13)*
Gate: hand-checked CSC · exact full-model reconstruction · l==u elimination equivalence on toy.
- [x] `config.py` — TOML load/resolve + CLI overrides + resolved-config echo (`gsmm-compiler config show`); unknown keys are errors
- [x] `model_input.py` — load, freeze reaction/metabolite order, validate, `model_report.json`, L0 key
- [x] `native_csc.py` — `NativeCSC` dataclass, column-wise builder, validation, `matvec`/`rmatvec`, **int32** index width (see facts above)
- [x] `flux_polytope.py` — `FluxPolytope` + **reduced polytope IR**: eliminate l==u, `v_full = R·v_red + c`, affine RHS `S_F v_F = -S_fixed v_fixed`
- [x] L0/L1 content hashing + provenance keys (parser/cobra/schema versions, dtype **and byte order**) → `provenance.py`
- [x] unit tests: CSC hand-check + order preservation + NaN/inf/dup detection + elimination & reconstruction round-trip
- [x] **gate**: LP optima identical full-vs-reduced under 200 random objectives (toy) and 10 (genome-scale) — feasible-set *and* objective equivalence, incl. the fixed-flux objective constant

### ✅ M2 — One-dimensional kernel (math oracle)  *(gate passed 2026-07-13)*
Gate: analytic + property tests across κL ∈ {0,±1e-16,±1e-12,±1e-8,±1,±100,±1000}; continuity; monotone slopes; edge cases.
- [x] `line_geometry.py` — feasible chord `[t_lo,t_hi]`; **keep all nonzero direction components**; `nextafter` inward; **self-loop (not redraw) on a degenerate chord**; raises on an empty or non-finite chord
- [x] `line_distribution.py` — breakpoints `τ_r=-v_r/d_r`; piecewise-linear concave `J(t)` via slope drops `2λw_r|d_r|`; **peak-anchored heights + higher-endpoint mass anchoring**; segment log-masses (`expm1`/`log1p` + custom logsumexp); categorical segment choice; stable truncated-exp inverse-CDF
- [x] unit tests: chord (±/zero comps, tiny-but-binding comps, t=0, degenerate); piecewise J vs direct grid eval, continuity, nonincreasing slopes, duplicate/near-duplicate/no breakpoints; `log φ` vs a **60-digit `decimal` oracle** across every regime
- [x] statistical tests: uniform (β=0), `e^{κt}`, `e^{-α|t|}` — KS vs exact analytic CDFs + an independent fine-grid quadrature of the *directly evaluated* `J`; fixed seeds, p-floor 1e-3
- [x] 🤝 **`/collab` adversarial review — 4 rounds, converged (AGREE, contested: none).** Found **two distribution-corrupting bugs that passed 264 tests**. See `.collab/specs/collab-outcome.md`; BUILD_PLAN §1.6 deltas 6–9 are new.

### ✅ M3 — Native HiGHS LP layer  *(gate passed 2026-07-13)*
Gate: solver objective == direct J · feasibility on degenerate toys · z=|v| within tol · no scipy.
- [x] `highs_backend.py` — `HighsLinearProgram` adapter: build `HighsLp`, `passModel`, `set_objective`/`set_maximize`, `solve` w/ status+model-status checks, one-shot solution extraction, basis get/set, **solve counter** (process-global) + `freeze()`
- [x] `sparse_objective.py` — `SparseFluxObjective`; (v,z) LP by **direct CSC assembly** (no scipy blocks); z=|v| checks; biomass-only diagnostic LP; recompute + compare J; `SparseObjectiveSolution` (the L2 bundle: J*, v*, μ*, C*, μ_max, retention, **sparsity-dominated flag**)
- [x] unit tests: analytic toy optimum, solver-obj==direct-J, z=|v|, feasibility, λ sensitivity, biomass excluded by default, custom weights
- [x] **gate**: solver obj == direct J on toy + genome-scale across λ ∈ {0, 1e-4, 1e-3, 0.01, 1}; v* feasible in the *full* 773-reaction polytope; degenerate toys (singleton / infeasible / unique-point / tied optima / λ=0) all classified right; no scipy
- [x] **addendum (settled by user, 2026-07-13)**: λ is **scale-referenced** — `critical_l1_penalty` (exact λ*, one Charnes–Cooper LP), `origin_is_feasible`, `resolve_objective`; config takes dimensionless `l1_penalty_scaled`. See BUILD_PLAN §1.7

### ✅ M4 — Affine geometry + span certificate  *(gate passed 2026-07-13)*
Gate: known toy dims recovered · truncated basis rejected · ‖S·diag(s)·B‖≈0 · singleton path.
- [x] `affine_geometry.py` — scaled coords `s_i`; orthonormal basis (2-pass projection, Fortran-contig, block-allocated); support-LP discovery w/ warm starts; memory guard before **every** allocation
- [x] **deterministic span certificate** — probes an orthonormal basis of range(B)ᗮ (pivoted Gram-Schmidt over the axes, ordered by residual norm); random probes are the pre-pass; a failing sweep *hands back the missing direction*; capped/inconclusive runs are refused unless explicitly downgraded
- [x] **`blocked_reactions` + `DirectionSpace`** (beyond spec) — FVA finds the 61 free reactions that cannot move; their components, and any non-mass-balanced ones, are projected out of every candidate exactly. Without this, the chord at the centre excluded `t = 0` and M5 could not start
- [x] feasible center from support points; **exactly** bound-feasible (clamp bounded by the LP tolerance, mass balance re-verified); chords at the centre validated; geometry diagnostics + manifest
- [x] tests: known toy dims (triangle/narrow/singleton/pinned), orthonormality, mass-balanced directions, **truncated basis rejected (all 46 columns, one at a time)**, dim-0 singleton returns a constant, memory guard, determinism
- [x] **gate**: `d = 46` on the genome-scale model, matching an **independent FVA+rank oracle** that shares no code with the geometry; certificate exhaustive (214/214 probes, 0 inconclusive); a 500-step hit-and-run walk stays feasible in the *full* 773-reaction polytope with **zero** HiGHS solves
- [x] 🤝 **`/collab` adversarial review — 6 rounds.** Found a crash, a silently dropped dimension, a dual-side blind spot, an accumulating basis error, an unsound bound formula, and **two test bugs** (one made a test unable to fail). All reproduced before fixing. See `.collab/specs/collab-outcome.md` § M4

### ✅ M5 — Rounding + β=0 sampler  *(gate passed 2026-07-14)*
Gate: uniform analytic targets reproduced · transform-invariance · ‖ST‖≈0 · **zero inner-loop HiGHS solves**.
- [x] `rounding.py` — support-point covariance, ridge (rel. to trace/d) + geometric escalation, Cholesky `L`, `T=diag(s)BL`, ‖ST‖ check (relative, unfloored), **SVD rank check on `T`**, physically read-only arrays, per-coordinate precompute derived from `T` and validated against it
- [x] `maxent_sampler.py` (β=0) — coordinate hit-and-run, reduced state `y` + incremental `v` on the structural support only, periodic exact refresh, **stored flux is the exact `centre+T·y` of the stored state**, SeedSequence keyed on `(model_id,stage,β,chain)`
- [x] multi-chain (4, dispersed Dirichlet(0.5) starts over the support hull); `diagnostics.py` split-R̂ / Geyer ESS / autocorr / feasibility
- [x] tests: **the 2-simplex** (marginal `2(1−x)`, *not* uniform — the target a box cannot distinguish), coupled box, anisotropic box, transform-invariance of moments (ESS-normalized z, not σ), positive chords at start, solve-counter==0
- [x] 🤝 **`/collab` adversarial review — 3 rounds, converged (AGREE, contested: none).** Found **six defects that 553 tests passed over**. See `.collab/specs/collab-outcome.md` § M5; BUILD_PLAN §1.6.1 is new.

### ✅ M6 — Positive-β maximum-entropy sampler  *(gate passed 2026-07-14)*
Gate: truncated-exp + truncated-Laplace targets · mean J nondecreasing in β · 1D quadrature cross-check.
- [x] wire exact piecewise-exp line conditional (M2) into the sampler for β>0 — the kernel is **unchanged**; M6 supplies inputs (BUILD_PLAN §1.6.2)
- [x] `lower_objective` → `ReducedObjective` (the kernel's `L1Objective` in **reduced** coords + the fixed-flux μ/C constants); `L1Objective.biomass_index` is now `int | None` (a *fixed* biomass is a constant)
- [x] explicit β-ladder (`run_ladder`, `SUGGESTED_BETA_LADDER`); energy scale `s_J` from the support points (`choose_energy_scale`, spec §22.2); objective traces (μ, C, J, normalized log-energy, near-zero counts over the **movable** reactions)
- [x] feasible starts: `v*` joins the dispersed support hull (`optimum_coordinates`); flux → reduced coords via `RoundedTransform.to_coordinates` (a `numpy.linalg.solve` against `L`)
- [x] **statistical gate** (`tests/statistical/test_tilted_targets.py`): truncated exponential (no breakpoints) · **asymmetric truncated Laplace** (interior bend, 3:1 slopes — the load-bearing one) · coupled `(1−x)·e^{γx}` simplex marginal · **reduced-coordinate quadrature cross-check** that evaluates `J` from its definition and never touches the piecewise machinery · large-β stress (β = 1000) · a *failing control* for every one
- [x] **integration gate**: mean J rises 3.14 (**6.9σ**, monotone, R̂(J) ≤ 1.07) and **matches the linear-response prediction** `β·Var₀(J)/s_J = 3.44` — which pins the *magnitude* of κ, not just its sign · every sample feasible in the full 773-reaction polytope · **zero HiGHS solves** with the objective live in the inner loop
- [x] 🤝 **`/collab` adversarial review — 6 rounds. Found 12 defects, and by round 5 they were visibly one bug**: *two artifacts that were never computed against each other, silently joined*. See `.collab/specs/collab-outcome.md` § M6; BUILD_PLAN §§1.6.2–1.6.4, §2.1 are new.

### ✅ M7 — Reweighted-L1 (frozen weights)  *(gate passed 2026-07-16)*
Gate: deterministic weights (fixed seed) · active-set converges · weights frozen before MCMC · targets reproduced under reweighted J.
- [x] reweighting loop `w_r ← w_base/(|v_r|+ε)`, clip to limits, median-renormalize, stop on **weight-fixed-point** + active-set tol (`reweighting.py`)
- [x] save every weight vector + LP solution (`ReweightingStep`); **freeze final weights** (physically read-only), rebuild objective/LP-opt/`s_J` from them (`ReweightingReport`)
- [x] label experimental (not exact cardinality); guard: reweighter structurally cannot import the sampler and vice-versa — weights can never update from MCMC state
- [x] **λ decision settled** — `λ_k = λ̃·λ*(w_k)` re-resolved each iteration (frozen λ collapses the pressure 0.5→4e-6 and crashes M3's z==|v| gate by iteration 2; both measured). BUILD_PLAN §1.7
- [x] tests: weight formula, clipping/renorm, scale-invariance (median is a no-op), determinism, frozen-before-sampling, weight-vs-flux convergence, no-op detection (`n_shed`/`support_unchanged`), and the M7 integration gate (134→131 shed, **zero HiGHS solves after freeze**, every tilted sample feasible in the full 773-reaction polytope)
- [x] 🤝 **`/collab` adversarial review — 5 rounds, converged (AGREE).** Found the convergence metric was flux-based and blind on small coordinates, `n_shed` was net-only, `LPOptimum` and the warm-up array lacked polytope keys, and the clip ratio was unbounded. All fixed. See `.collab/specs/collab-outcome.md` § M7; BUILD_PLAN §1.6.5 is new

### ✅ M8 — Cache, restart, batch orchestration & production  *(gate passed 2026-07-16)*
Gate: resume only missing (model,chain) units · partial batch → valid cross-model tables · concurrent-writer safe · deterministic same-env traces.
- [x] `output.py` — run-dir layout, atomic temp+rename+fsync, per-chain + run `COMPLETE` markers, staged-directory publish, validated array persistence, configurable storage (`full_flux` f64/f32 · `reduced`)
- [x] `cache.py` — layer-generic content-addressed store + **writer-claim (atomic mkdir)** + wait-for-`COMPLETE` + stale-claim steal + on-load hash validation; geometry (L3) wired via `RoundedTransform.to_bundle`/`from_bundle`
- [x] **batch runner** (`batch.py`) over a models manifest (`.json`/`.tsv`); one **global** `spawn` process pool over `(model,β,chain)`; OPENBLAS/OMP/MKL threads=1 set before the pool; workers write own files and **never import cobra/HiGHS**; per-unit resume; a failed strain is recorded, not fatal
- [x] **cross-model aggregation** (`features.aggregate_cross_model` → `results/<batch>/cross_model/`: β-summary JSON+TSV, reaction-activity, exchange-flux) — reads only per-model artifacts, so a partial batch still yields valid tables
- [x] `diagnostics.run_diagnostics`/`write_run_diagnostics` (feasibility/objective/mcmc/geometry/solver JSON, incl. per-β R̂(J)/ESS(J) and E[J] monotonicity) + `features.py` (active-fraction/mean-abs/mean flux; pathway deferred — needs subsystem annotations the example models don't carry)
- [x] full CLI: `maxent solve-lp | build-geometry | sample | batch | diagnose`
- [x] the M8-scoped **L0 key defect fixed first** (content-addressed identity, BUILD_PLAN §1.1)
- [x] tests: kill-and-resume (only the missing unit recomputes, verified by mtime + bit-identical reproduction), concurrent-writer (8 threads → compute once), corrupted-artifact rejection (sample + cache), batch ≥2 strains + one deliberately failed → valid cross-model tables, serial==pool byte-identical, zero HiGHS solves in the sampling loop, every sample feasible in the full polytope

### ✅ M9 — Performance & GSMM hardening  *(gate passed 2026-07-16)*
Gate: benchmark report produced · all performance assertions hold.
- [x] `benchmark.py` (new module, not in spec §6) + `gsmm-compiler maxent benchmark` CLI — every stage timed: parse→CSC→reduce→passModel→first LP→warm-start LPs→sparse LP→geometry→rounding→β=0 sps→β>0 sps→breakpoint kernel→output. Report: [benchmarks/M9_REPORT.md](benchmarks/M9_REPORT.md) + `bifido_benchmark.json`
- [x] worker-count sweep {1,2,4,7,14} by **ESS(J)/wall-sec** — 14.77 ESS/wall-s at 14 workers (7.76× speedup, 55% efficiency); **ESS(J) spread exactly 0 across worker counts**; decay is Amdahl (f = 4.0%, ceiling 24.9×), not contention
- [x] allocation + breakpoint-sort profiling — **the sort is *not* the hot spot** (median 2 breakpoints/chord); `validate()` + `baseline` are 18% of every β>0 update and the draw uses neither
- [x] `reduced` storage mode validated at genome scale — round-trips to 1.1e-13 (**not** bit-exact: gemv vs gemm), cheapest to write (34.4 µs/sample)
- [x] assert: no per-step HiGHS · no scipy (against a *live run*) · no Python loop in chord (7.6 vs 710 ns/reaction, both measured before the bar was set) · no element-wise highspy extraction · no full reconstruction every step (asserted **differentially**)
- [x] 🔴 **scope added mid-milestone**: the **reachable-state mass-balance certificate** (BUILD_PLAN §1.4.2). The benchmark's own worker sweep could not run — M5's `‖S·T‖` gate rejected a valid genome-scale geometry on **8 of 24 RNG streams**. 🤝 `/collab` **2 rounds, converged** — Codex killed my proposed fix with a counterexample; I conceded 4 points, it conceded 1

### 🔴 Open for M10 (found by M9, deliberately not fixed here)
- **The span certificate is a second RNG-marginal gate**: `build_geometry` raises "not exhaustive (214/214 probes, 1 inconclusive)" on ~1–2 of 20 streams. Same shape as the §1.4.2 defect (a tolerance at the noise floor), not diagnosed.
- **The β>0 kernel spends ~18% of every coordinate update on work the draw never reads** — `PiecewiseLinearJ.validate()` (11.8 µs) and `baseline` (6.5 µs, an absolute `J` that provably cancels out of `p(t)`). Untouched because `line_distribution` is the math-critical M2 kernel and removing a correctness check is a design fork BUILD_PLAN does not settle.

### 🚧 M10 — Extensions  *(ACTIVE)*

#### ✅ M10.1 — pilot rerounding + pilot-based `s_J`  *(gate passed 2026-07-16)*
- [x] `calibration.py` (new module) — `NeutralPilot` (frozen, **objective-independent**, keyed on polytope+transform+schedule+stage), `run_neutral_pilot`, `calibrate` (the DAG), `CalibrationResult`
- [x] `rounding.reround_transform` — `T₁` from the pilot's covariance via the exact identity `q = L₀·y`; `build_transform` and it now share one `_transform_from_coordinates`, so the two estimators cannot drift apart. `RoundingDiagnostics.covariance_source` records which; `ROUNDING_IMPL_VERSION` → 2 so v1 bundles **miss** the cache rather than erroring on a hit
- [x] `sparse_objective.pilot_energy_scale` + `PilotScaleReport` — `s_J = σ̂₀`; reports Δ₀, `G`, R₉₀, skew, excess kurtosis, R̂(J), between-chain σ̂ ratio, and a **kurtosis-aware centered-square** `relative_se`. `J*` is key-checked but **cannot move `s_J` by an ULP** (3 artifacts → 2)
- [x] config: `energy_scale="pilot_sd"` (additive), `pilot_reround`, `pilot_chains/burn_in/samples`
- [x] **the RNG-stage defect** — `run_chain` hardcoded `stage="sample"`, so both pilots drew identical numbers; `stage` is now a parameter (found by a test written from the design argument)
- [x] tests (37): the range identity `range(T₁) = range(T₀)` both ways · full column rank · `q = L₀·y` vs an independent projection · **`support_coordinates` stay the vertex hull, not the pilot draws** · arrays physically read-only · **the sampler cannot import `calibration`** (subprocess) · pilot-stage independence · reproducibility · key coverage · `s_J` vs hand-written arithmetic · shift-invariance at +1e12 **with its premise asserted** · degenerate-spread refusal · precision **warns, never gates** · every artifact-join refusal
- [x] 🤝 **`/collab` adversarial review — 4 rounds, converged (AGREE).** It falsified the tracker's own prerequisite, then killed five of my overclaims. See `.collab/specs/collab-outcome.md` § M10; BUILD_PLAN §1.6.6 is new

#### ✅ M10.2a — DAG identity + CLI wiring  *(gate passed 2026-07-16)*
- [x] **measured the recorded fork before building it**: geometry 1.168 s vs pilots 19.202 s (16.4×) — a layer for `T₁` (9 ms) would key the wrong stage. The blocker was **plan/code drift**, not a fork: §1.1 always said L3 holds `B` + the span certificate, and `ReducedGeometry` had no serializer
- [x] `ReducedGeometry.to_bundle`/`from_bundle` + `SpanCertificate`/`GeometryDiagnostics` `to_cache`/`from_cache` (field-named — `as_dict` renames and injects the derived `resolution`); `content_key` now hashes `support_points`; `GEOMETRY_IMPL_VERSION` → 2 so a v1 bundle **misses** rather than `KeyError`s on a hit
- [x] `batch.build_l3_bundle` — the **one writer** of the L3 schema; the CLI's `--cache-dir` path calls it instead of assembling a second one. Geometry arrays namespaced (`ReducedGeometry.center` and `RoundedTransform.center` would collide in a flat merge)
- [x] 🔴 **v1 defect**: `require_certified_transform` on **every** load path, not just the miss — it checks the polytope, the **transform** (`ReachabilityCertificate` gained a `transform_key`; `T₀`/`T₁` share a `polytope_key` exactly), and **re-derives the verdict against the policy**
- [x] ⚠️ the pilot's objective-dependence: `run_neutral_pilot` has **no** `optimum_coordinates` (structural, not defaulted-`None`); `content_key` += `seed`, `refresh_interval`, `sampler_impl_version`; `CALIBRATION_IMPL_VERSION` → 2 (a *removed* input leaves no trace in a key)
- [x] `calibrate` certifies `T₁` **before the scale pilot** and requires a `bootstrap_certificate`; `CalibrationResult.certificate` is always the proof for the transform it ships
- [x] 🔴 **v1 defect**: `batch.sample_recipe_key` (§1.1's sample key, specified from the start, computed nowhere) written into every manifest; `_already_done` **refuses** a foreign `COMPLETE`; new `output.OUTPUT_IMPL_VERSION` (the writer decides the bytes; `SAMPLER_IMPL_VERSION` is the kernel)
- [x] `prepare_model` routes **every** run through `calibrate` with no branch — switches off ⇒ `T₀` + `warmup_range`, v1's numbers with v1's labels
- [x] tests (23): each fails on its own bug (verified by reverting the fix — poisoned cache "DID NOT RAISE"; the pilot key's *identical* hashes; the manifest's lost verdict; "optimum_coordinates changes the samples but not the recipe key"; the relaxed bar), each with its premise asserted
- [x] 🤝 **`/collab` adversarial review — 4 rounds (this milestone), converged.** It falsified the tracker's framing, found the two v1 defects' full shape, then found a defect **I introduced** (the manifest naming `T₀` while production sampled `T₁`) and the hole behind each of my repairs. See `.collab/specs/collab-outcome.md` § M10.2; **BUILD_PLAN §1.6.7 is new**
- [x] end-to-end: `maxent sample --set sampler.energy_scale=pilot_sd --set sampler.pilot_reround=true` runs the DAG (`T₁` certified 3.86e-11, 26× inside contract); an identical recipe **resumes** (4.0 s vs 12.5 s), a changed schedule **refuses** with an actionable message and does not sink the batch

#### ✅ M10.2b — cache the pilots  *(gate passed 2026-07-16)*
Measured first: the pilots are **19.2 s of serial parent work** per model, so a restart re-ran them before resuming one chain and M9's Amdahl ceiling of 24.9× fell to ~3.65×. Result: `prepare_model` **23.08 s → 1.17 s warm (19.6×)**, `T₁` key and `s_J` bit-identical cold vs warm vs no-cache.
- [x] the payload split (geometry pilot → coordinates; scale pilot → reduced fluxes), after `/collab` round 1 **killed my objection to it** — `not np.allclose` proves non-identity, not independence
- [x] **the gate goes *before* the dispatch**, not in the `compute()` closure that runs only on a miss — proved by moving it back and watching the hit-path test fail with DID NOT RAISE
- [x] the pilots honour `geometry.feasibility_tol` (they had silently used the 1e-9 default while production used the configured value) — and the key covers it, or it becomes a false-hit generator
- [x] 🤝 **`/collab` — 3 rounds.** Round 3 opened DISAGREE **on the built diff** and found an asymmetry *inside my own repair*: a lie in `polytope_key` keys identically, so a warm cache served what a miss refused. `require_pilot_inputs` is now the one place both paths ask
- *(the "two-phase dispatch" originally bundled here became **M10.2c** and is still open — see Next action)*

#### ✅ M10.2d — cache L0  *(gate passed 2026-07-17)*
The arithmetic set the scope, as it has every time: warm, `.reduce()` (L1) is **1 ms** and objective+LP (L2) **45 ms** against `load_canonical_model`'s **1.157 s**. §1.1 names four layers; **three are live** (`L0`, `L3`, `pilot`) — *the numbered layers describe the dependency structure, not a shopping list of stores.*
- [x] `prepare_model` **22.9 s → 0.645 s warm (35×)**, `T₁`/`s_J` bit-identical; the L0 hit costs **4 ms**
- [x] **a warm run never imports cobra** — the prize was bigger than the parse (cobra's own import is 0.65 s, *54% of the cost*), so the key reads package **metadata**, never `cobra.__version__`
- [x] two keys, not a hedge: `model_lookup_key` over the *inputs* (1 ms) + `l0_key` **re-derived on every load** as the authority — you cannot fingerprint a model's contents without parsing it
- [x] its CLI check then found the v1 threading defect that predates it → M10.2e

#### ✅ M10.2e — geometry determinism: the L3 artifact was not a function of its key  *(gate passed 2026-07-17)*
🔴 **The blocker is cleared**: `maxent sample` now completes from a clean cache under default threading (4/4 units, `T₁` certified 3.87e-11). One L3 key named **two bases**, chosen by an environment variable nobody set — §1.1's rule violated in v1's own geometry since M4. Full reasoning: **BUILD_PLAN §1.6.8**.
- [x] `numerics.deterministic_blas` — a **forced, scoped** BLAS limit, and both words are tested: a caller who exports `OMP_NUM_THREADS=8` still gets the keyed basis, and the caller's process is not touched outside the scope. Measured equivalent to an env-pin **bit-for-bit** (`55d39f6b87`), which is why a runtime limit replaced BUILD_PLAN's `os.environ` phrasing — BLAS reads those at load time, so a `setdefault` after NumPy imports changes nothing
- [x] **the scope was wrong in the spec, in both directions, and measurement fixed it.** `build_transform` is sensitive *independently of the basis* (`8e587b6ad5` vs `9d334b3f31` with the basis held fixed) — scoping the basis alone would have left half the defect. The **sampler is not** (draws bit-identical at 1 vs 14 threads with its inputs frozen), so it gets no scope. Three constructors, each verified
- [x] **the L3 key moves** (`DETERMINISM_POLICY_VERSION`), or caches already holding an ambient-thread basis stay valid hits and the fix reaches nothing that was warmed
- [x] **visibility beside elimination**: `numerical_identity` in every bundle — recipe key, basis/`T₀`/support hashes, policy version, BLAS vendor/version/**architecture**/threads. The recipe key is a **gate** (a bundle must answer to the key it is stored under); a foreign runtime **warns** (refusing would make caches unshareable — the cost that ruled out keying the thread count)
- [x] §1.1's promise restated: **within a declared numerical-runtime profile**, a recipe key rebuilds deterministically; across profiles byte equality is not promised (OpenBLAS `DYNAMIC_ARCH` picks kernels by runtime CPU detection). `s_J` is reproducible **in distribution**, not bit-for-bit, across machines
- [x] **the R̂ bar was never a threading problem** — measured across 8 seeds at 1500 draws, R̂ spans **1.089–1.177** and min ESS **10.2–50.7**: the bars sat *inside* the distribution of valid runs and seed 0 failed **both**. Fixed the **schedule** (4000 draws → R̂ 1.033–1.059, ESS 59.7–155.0 across 5 seeds; 2.5× and 3× margin), not the bar. M9's coin-flip lesson, a third time
- [x] the policy is **free — it pays**: `build_geometry` **1.170 s pinned vs 1.488 s at 14 threads (21% faster)**; a 260×46 Gram-Schmidt is too small for 14 threads to repay dispatch overhead
- [x] tests (16): thread-invariance **proved non-vacuous first** (the defect is reproduced through `build_geometry.__wrapped__` before the fix is asserted, so a thread-invariant CPU skips rather than passes hollowly) · forced · scoped · nesting · key bump · the identity gate · the foreign-runtime warning · the two policies stay separate. ⚠️ **They compare against `os.cpu_count()`, not the ambient count**, and the difference is their whole grip: keyed off ambient, all four thread comparisons **skip** under `OMP_NUM_THREADS=1` — precisely the environment a careful user or CI sets — and *four silently-skipped tests in a green suite read exactly like four passing ones*, which is a small copy of this milestone's own disease. `threadpoolctl` can raise **above** an env pin (measured: pinned to 1, raised to 14), so they prove themselves in both: **16 passed, 0 skipped, ambient and pinned alike**
- [x] 🤝 **`/collab` — 1 round (AGREE, 2 corrections to my claims)**, before the build. It refuted the tracker's "§1.2 mandates this and the code drifted" framing: there is **no drift, there is a gap** — *two requirements that share a mechanism are still two requirements*
- ⚠️ 🤝 **round 2 on the built diff was attempted and ABORTED — no verdict, and it is not counted as one.** Codex's bubblewrap sandbox could not create user namespaces here, so it fell back to **fetching the repo from GitHub at commit `07a8a4f` (M10.2a)** — reviewing code three milestones stale; and `numerics.py`, being untracked, **appears in no `git diff`**, so the milestone's central file was invisible to it by construction. *If re-run, inline the code in the prompt.* Its one lead was taken and **converged with my own probe** (the scopes cover `T₀`/`T₁` construction but not the keyed chains consuming them, and `certify` runs after the decorator exits): both measured **invariant**, and both now pinned by tests, because the original test hashed only `coordinates` — **defending a claim broader than the one it checked**. See `.collab/specs/collab-outcome.md` § M10.2e round 2

#### ⬜ M10.3+ — the rest  *(deferred behind M11 — none of it matters while 36 of 40 strains cannot be sampled)*
β→performance calibration (spec §22.3 — now cheap: `q(β)` and `r_eff(κ)` already exist); the β>0 kernel's 18% of unused work; parallel tempering; slice-based line kernel; downstream mode-feature discovery. Each behind its own tests; none alters the validated v1 target. **The span certificate's RNG-marginal gate moved to M11.2** — it is a v1 defect on the real batch, not an extension. **Pilot-chain pooling is dropped**: measured at +0.7% (§1.6.9).

---

### 🚧 M11 — v1 on the real batch  *(ACTIVE — BUILD_PLAN §1.6.11)*

Gate: `build-geometry` succeeds on the curated 40, or refuses for a reason that is a property of the
**model** rather than of the RNG stream. Every remedy names the measurement confirming its premise first.

#### ✅ M11.0 — the L3 lookup key names its solver  *(gate passed 2026-07-17)*
- [x] **measured the batch before touching anything**: 40 curated strains, default config, the intended inputs (the example model is **byte-identical** to the curated one; `ModelSpec` takes only path/biomass/id, so there is no medium to apply). **4 succeed.** 24 blocked/moving · 9 `kUnknown`@`flux_only` · 2 span certificate · 1 `kUnknown`@`reachable_mass_balance`
- [x] `highs_backend.solver_identity()` — `BACKEND_IMPL_VERSION` + the installed HiGHS version, read via `importlib.metadata` so **computing the key never imports the solver** (M10.2d's warm-run property, which the key exists to protect); folded into `batch.geometry_cache_key`; `BACKEND_IMPL_VERSION` → 2, which is the fix's own first live exercise
- [x] **forced first, and that is Codex's finding, not mine**: every remaining M11 item changes solve bytes. A bumped `BACKEND_IMPL_VERSION` was found under the deficient lookup key as a **hit** and then died on the content key — §1.1 requires a **miss**, never an error on stale bytes (`GEOMETRY_IMPL_VERSION`'s own docstring records that exact mechanism for its bump). The **silent** half is the HiGHS version, absent from **both** identities: a `uv sync` served a cache warmed by the previous solver, and L3's support points are LP outputs
- [x] scope measured, not assumed: **three live stores** (L0, L3, pilot). L2 has a key and **no store**, so `BACKEND_IMPL_VERSION`'s "L2/L3 cache keys" is aspirational. The pilot key hashes `transform_key` → `geometry_key` → the backend version (transitively covered, and it runs no LPs); L0 involves no LP. **L3 was the only gap**
- [x] tests (4): both key tests **fail on the shipped code with an identical digest** · the end-to-end test proves the *behaviour* §1.1 wants (a warm entry rebuilds under the new name rather than erroring) · the subprocess isolation test is **proved non-vacuous by sabotage** (patching `solver_identity` to read `highspy.__version__` makes it fail)
- [x] ⚠️ **the suite caught a bad test of mine** — it passed alone and failed in the suite, because `'highspy' not in sys.modules` is **global interpreter state**, not a property of the key: green or red by test *order*, testing nothing. M10.2d's cobra test already says why in its own docstring (*"In a subprocess, because a module another test already imported would make this pass for free"*). The difference between a green test and evidence is having seen it fail on the broken code

#### ✅ M11.1 — `blocked_reactions`: the third state + one bounded cold escalation  *(gate passed 2026-07-17; the disease is fixed, one deterministic residue documented)*
- [x] 🤝 `/collab` **before** the build (M4, math-critical), and again to close. **Codex DISAGREED three times and was right each time** — see below; I adopted its wording, not mine.
- [x] the third state — certified BLOCKED (`U ≤ tol`, weak duality, no primal) / **resolution-qualified** MOVING (`L > tol` strictly, `L = W − NOISE_SAFETY·2·admitted − eps·reach` rounded outward) / **UNRESOLVED**. ⚠️ **MOVING is never "certified"** (Codex): turning a constraint residual into a distance from the exact feasible set needs a Hoffman constant this package does not have, so the primal side is resolution-qualified, matching §1.4.1's own honesty applied at last to *both* sides
- [x] `U` and `L` stored **separately**; `L > U` **raises loudly** — the predecessor's `max(U, W)` could not observe a contradiction because it resolved it (Codex)
- [x] `kUnknown` yields *no witness* → UNRESOLVED, so the 9 crashes and the misclassifications are the **same case**; caught **caller-side**, `HighsLinearProgram.solve()` unchanged (`critical_l1_penalty` still needs `LPNotOptimalError`)
- [x] one bounded cold escalation, **fully cold — a fresh instance per *solve*, not per reaction**. 🔴 **The census exposed this bug**: my first cut shared one fresh instance for a reaction's `max` and `min`, so `min` warm-started off `max` — one step of inherited history — and **10 of 40** falsely refused. Decomposed *L. brevis* (`1/372`): fully cold, 0 straddle; the straddler existed only because `min` inherited `max`'s basis. Discriminator: *Hafnia* stays unresolved **both** ways (`U = 2.05e-9`, `admitted = 1.5e-12`, allowance 3e-11 — not inflated), so the fix separates the artifact from the real floor case exactly
- [x] `GEOMETRY_IMPL_VERSION` → 3 (an *algorithm* change above the solver; M11.0's `BACKEND_IMPL_VERSION` bump does not cover it — Codex); `min_separation` demoted to a diagnostic; `n_blocked_escalated` reported
- [x] **census (build-geometry, all 40, fully cold): OK 4 → 20**; `blocked_reactions` refuses exactly the **2 *Hafnia*** strains; 8 `kUnknown@flux_only` + 4 span + 5 `kUnknown@reachable` + 1 centre are **later stages** (M11.2/M11.3), unmasked now that the earlier crash is gone
- [x] tests (5 new / rewritten): the three-state classification · a `tol` between two real widths now *classifies* instead of refusing (separation gate gone) · the refuse path on a genuine floor · a `kUnknown` warm solve **recovered by cold escalation** (injected via a wrapper — non-vacuous) · the contradiction guard. 965 green; ruff + mypy clean
- 🔴 **The stated gate — "no reaction unresolved after escalation" — is NOT met, and this milestone must not pretend it is** (Codex, closing review). *Hafnia* leaves 2 unresolved. What M11.1 actually fixed is the **disease**: the RNG-marginal refusal, where the warm-start path (driven by the RNG solve order) decided the verdict. `blocked_reactions` takes **no seed/model_id** at all, so its refusal is now a **structurally deterministic** function of the model file — the coin flip is gone. **What it did *not* establish**: that *Hafnia*'s true width is zero. `U > tol` proves only *uncertified-blocked*; it is a **repeatable certificate floor**, cause (conditioning vs genuine flatness) not settled. Deferred: a stronger blocked certificate, or documented `blocked_tol` guidance so the user declares the resolution. **This is a real remaining gap in "v1 runs on the batch", not a closed one.**

#### ✅ M11.2 — span gate `resolution ≤ span_tol` + build-wide solve session  *(gate passed 2026-07-18; disease fixed, residues deferred)*
- [x] 🤝 `/collab` **design review before build** (measurement-first, as required) + **closing review** (DISAGREE×1, 4 discrepancies fixed). See [.collab/specs/m112-span-and-session.md](.collab/specs/m112-span-and-session.md).
- [x] **required measurement first**: the paired warm-vs-fresh experiment confirmed all 3 tested `kUnknown@flux_only` are warm-start history (kUnknown WARM → kOptimal COLD); a strain marked SPAN-CERT-REFUSED under its own `model_id` builds with `n_inconclusive=0` under another (RNG-marginal, §1.6.10); `lactis` has `n_inconclusive=2` but `resolution=5.36e-11 ≤ span_tol` — the decisive case for the gate.
- [x] **(A)** span `exhaustive` = `failing is None and complete and not capped and resolution ≤ span_tol`, one extracted `_span_resolution()` for both the property and the gate; `n_inconclusive` a diagnostic. The §1.6.10 seed-lottery cases (`strain_1`/`strain_11`, resolution 2.7e-11) now build — the tracker's original #1 defect, closed. Non-vacuous test: `strain_1` raises on the v3 gate, passes on v4.
- [x] **(B)** a build-wide `_SolveSession` owns the LP instance: warm until the first `kUnknown`, cold-only after — fixing the leak Codex found (M11.1's `warm=None` was function-local while `build_geometry` reused the same program). `blocked_reactions` keeps its cold-pair logic and calls `session.mark_degraded()`. `solve_fresh_once` is the one escalation primitive. A `resolution > span_tol` refusal is re-confirmed by a **fully-cold re-sweep** before it is final.
- [x] `GEOMETRY_IMPL_VERSION` → 4 (an algorithm change; cached diagnostic semantics move).
- [x] **census: build-geometry OK 20 → 30 of 40; `kUnknown@flux_only` 8 → 0**; control (Bifido) unchanged (`n_cold_solves=0`, `degraded=False`).
- [x] **the 4 closing-review fixes**: (1) `blocked_reactions` now escalates **only** `kUnknown` (`_reraise_unless_kunknown`; infeasible/unbounded stay hard failures) — proven by a test; (2) the cold pair uses `solve_fresh_once`; (3) `degraded_at`→`degraded: bool`, and each solve counter documents exactly what it counts + the serialized-build assumption; (4) the **8-seed sweep** demanded by Codex.
- 🔴 **(4) changed a conclusion — the sweep *split* the 2 span residues.** I had called both "genuine, deterministic, confirmed cold"; a cold re-sweep keeps the RNG-discovered basis, so a different `model_id` gives a different resolution — I had measured one seed each. **pumilus: 8/8 refuse** (2.35e-9…5.20e-9, d=88) → a **genuine √k floor**. **Liquorilactobacillus: 3/8 pass** (7.67e-10…4.57e-9, d=56) → **RNG-marginal, not a floor** — `max_width` varies with the basis, so the resolution straddles span_tol; needs a **tighter, basis-independent** span certificate. Both deferred. *The multi-seed measurement is what caught my overclaim — again.*
- [x] tests (6 new: the span-gate integration case non-vacuous vs v3; three `_SolveSession` unit tests; `blocked_reactions` re-raises non-`kUnknown`; an **end-to-end** warm-resolution-failure → fully-cold re-sweep). 966 green; ruff + mypy clean.
#### ⬜ M11.3 — reachability's caller-specific dual-witness path  *(1 strain)*
#### ⬜ M11.4 — re-run the 40-strain census end to end  *(⚠️ rounding/pilots/sampler have **never run on an aerobe**)*
#### ⬜ M11.5 — release: LICENSE, README/docs, a manifest that reads the real `strains.tsv`

---

## Session log  (append one line per working session, newest last)

- 2026-07-13 — Design collaboration (Claude×Codex, 2 rounds) → BUILD_PLAN.md. Investigated blocked reactions (513 = FVA-blocked under anaerobic medium; fixed-var elimination provably correct). Locked scope: batch-aware v1, reweighted-L1 in v1 (M7), configurable storage, Python 3.11. Created this tracker + project CLAUDE.md. **No code yet — next session starts M0.**
- 2026-07-13 — **M0 gate PASSED.** Scaffolded `pyproject.toml` (hatchling, src layout) + all 17 modules of the spec §6 skeleton; `uv` venv on 3.11.15 with a wheel-only install (`uv.lock`, 47 pkgs, zero source builds). Smoke test builds the biomass LP from native int32/float64 CSC arrays, passes it to `highspy.passModel`, solves to `kOptimal`, and **matches cobra's own FBA optimum to rel=1e-6** — so the CSC assembly is verified, not just accepted. 25 tests green; ruff + mypy --strict clean. Findings: (a) **scipy is absent from the venv entirely**, so the no-scipy path is free rather than fought for; (b) **highspy attribute reads return Python lists, not NumPy views** — recorded for M3's one-shot extraction design; (c) BUILD_PLAN §0's "65 exchanges" was 63 `EX_` + 2 `SK_` sinks — corrected in place. **Next: M1** (`config.py` first).
- 2026-07-13 — **M1 gate PASSED.** Built `native_csc` (int32 CSC + `matvec`/`rmatvec` via `bincount`), `flux_polytope` (canonical + reduced IR with the explicit affine RHS), `model_input` (validation → canonical L0 IR + `model_report.json`), `config` (TOML + overrides, unknown keys rejected), and a new `provenance` module for L0/L1 content keys. Added `examples/toy_network.json` — 7 reactions, with **FIX pinned at 2.0** so the reduced mass balance is genuinely affine, the case the Bifido model cannot exercise (all 513 of its fixed reactions sit at zero). Gate closed by LP-level equivalence: full-vs-reduced optima agree under 200 random objectives on the toy and 10 on the genome-scale model, including the fixed-flux objective constant that §1.5 warns about. 164 tests green; ruff + mypy --strict clean. Findings: (a) **HiGHS uses a 32-bit `HighsInt`** (`kHighsIInf == 2**31-1`), so the spec's `int64` CSC would be silently narrowed on every `passModel` — we store int32 and bound-check nnz; (b) **cobra already rejects NaN/inverted/duplicate-ID models but accepts infinite bounds**, so that is the one malformation our parser layer must catch itself. `.collab/specs/collab-outcome.md` is referenced by three docs but **does not exist** (the directory is empty) — decisions survive in BUILD_PLAN §1. **Next: M2** (math-critical — `/collab` review required at the gate).
- 2026-07-13 — **M2 gate PASSED (math-critical).** Built `line_geometry` (feasible chord) and `line_distribution` (breakpoints → piecewise-linear concave `J` → segment log-masses → categorical choice → truncated-exp inverse CDF). 287 tests green; ruff + mypy --strict clean. `log φ = log(expm1(x)/x)` is checked against a **60-digit `decimal` oracle** rather than a restatement of itself, and the statistical tests KS the sampler against exact analytic CDFs *and* against an independent fine-grid quadrature of the **directly evaluated** `J` — a reference that never touches the piecewise machinery, so a misplaced breakpoint cannot cancel out against itself. **The `/collab` review ran 4 rounds and earned its keep: it found two bugs that corrupted the sampled distribution while 264 tests passed.** (a) *The absolute magnitude of `J` reached the probabilities.* `h_a = β(J−J*)/s_J` built from absolute knot values cancels catastrophically; with a biomass flux of 1e16 the true segment probabilities [0.387, 0.613] came back as [0.632, 0.368] — **the favoured segment reversed**, from slopes that were themselves exactly right. Fixed by storing knot heights relative to the **peak** of `J` and anchoring each segment's mass integral at its **higher endpoint**; `J*` left the API entirely (it provably cancels). (b) *Redrawing a coordinate on a degenerate chord breaks stationarity* — spec §19 and BUILD_PLAN §1.6 both prescribed it, but it makes coordinate selection state-dependent and collapses the random-scan Gibbs invariance argument. Now a **self-loop**, and there is no minimum chord width at all. Round 2 is the one to remember: **both of its findings were defects in round 1's fixes**, not in the original code. Also corrected: the opening slope (spec §20.3's midpoint rule reads `sgn(0)=0` on a one-ULP first segment and is 2× off in a measured 10.5% of them); `UNIFORM_LIMIT = eps/4`, not `eps/2`, because float spacing is asymmetric about 1.0; `β/s_J` validated against a *silent* underflow. I rebutted one Codex claim with measurements (the `MIN_NORMAL` "collapse" was ≤1 ULP on a probability-1e-15 set, not distribution corruption) and it conceded. BUILD_PLAN §1.6 gains **deltas 6–9**; `.collab/specs/collab-outcome.md` now exists and records all four rounds. **Next: M3** (`highs_backend.py` — not math-critical, no collab gate).
- 2026-07-13 — **M3 gate PASSED.** Built `highs_backend` (the only module that touches `highspy`) and `sparse_objective` (the objective, the (v,z) LP, the §14 flux-only LP, the biomass-only diagnostic). 369 tests green; ruff + mypy --strict clean. The gate is one equation — *solver objective == directly recomputed J* — and it is load-bearing: HiGHS optimizes a linearized surrogate over `(v,z)` on a **reduced** polytope with a constant folded into an **offset**, while `evaluate` computes `J` from the full 773-flux vector and knows none of that. They agree only if the linearization, the fixed-variable elimination, the objective lowering *and* the constant are all right. Verified on both models across λ ∈ {0, 1e-4, 1e-3, 0.01, 1}. Design notes: (a) HiGHS adds `lp.offset_` to the reported objective **sign-intact under `kMaximize`** — probed, then pinned by a test — so the fixed reactions' L1 cost reaches `J*` instead of being quietly dropped (only the toy, with `FIX = 2.0`, can catch that; all 513 of the example model's fixed reactions sit at zero); (b) a `z` column is built **only where `λw_r > 0`**, because a zero-cost `z` has nothing pushing it down onto `|v_r|` and would fail its own check on a solution that is perfectly correct in `v`; (c) the solve counter is **process-global** and programs can be `freeze()`d, so M5 can both assert and *prohibit* an inner-loop solve; (d) `highspy` is imported inside the constructor, so a worker can import the objective without loading a solver. **🔴 The milestone's real find is scientific, not structural: at the default λ = 1.0 the genome-scale LP optimum is *the origin* — `v* = 0`, `J* = 0`, zero growth — while `μ_max = 41.6`.** Above `λ* = max_v μ(v)/C(v)` the L1 cost of growing outruns the biomass it returns and the cell's best move is to shut down; on this model `λ* = 1.89e-3`, so our default is **529× past the cliff** and the spec's own suggested `0.01` is **5.3×** past it. Nothing inside the LP can see this — optimal status, zero residual, `z = |v|` exactly — so `solve_sparse_objective` now always solves the biomass-only LP too and flags `is_sparsity_dominated`. The collapse needs a feasible origin: this model has **no forced-flux reaction at all** (no `ATPM` lower bound), which is also why the toy (`FIX = 2.0`) cannot reproduce it and the genome-scale model can. **Decision left OPEN** (raw λ vs scale-referenced λ), recorded in BUILD_PLAN §1.7 — it does not block M4/M5 (geometry is λ-independent; β=0 ignores `J`) but **must be settled before M6 tilts by `J`**. **Next: M4** (math-critical — `/collab` review required at the gate).
- 2026-07-13 — **M3 addendum: λ is now scale-referenced** (the open decision from the gate, settled by the user). The config takes a **dimensionless `λ̃`** (`objective.l1_penalty_scaled`, default 0.5) and `resolve_objective` computes the raw `λ = λ̃ · λ*` per model. **`λ*` is exact, from a single LP** — `λ* = max_v μ(v)/C(v)` is a linear-fractional program, and the Charnes–Cooper substitution (`y = v·t`, `t = 1/C(v)`) turns it into "maximize `μ(y)` subject to a unit cost budget `C(y) ≤ 1`", with the bounds homogenizing into rows `l·t ≤ y ≤ u·t` and the absolute value linearizing by the same `z ≥ ±y` trick as §12. It reproduces the 40-step bisection to 8 figures and hits the fork toy's hand-derived `λ* = 1/2` to 10 decimals, so it is checked against arithmetic rather than against itself. λ* is **exactly** the cliff, not merely near it: at `0.999·λ*` the model grows, at `1.001·λ*` the optimum is the origin — pinned as a test on the genome-scale model. The λ̃ ladder is now the selection-pressure dial the study wanted: **λ̃ = 0 → 100% of μ_max retained, 0.25 → 95%, 0.5 → 60%, 0.9 → 30%**. `λ̃ ≥ 1` is *refused* when the origin is feasible (a guaranteed collapse, nothing to sample) and *allowed* when it is not — a model with forced maintenance flux, like the toy, cannot answer a large λ by shutting down and so has no cliff at all. Why this matters beyond one model: λ̃ = 0.5 resolves to `λ = 9.4e-4` on Bifido and `λ = 0.25` on the toy — **a factor of 265** — so a shared *raw* λ would have meant wildly different selection pressures across a batch while looking, in the config file, like a controlled comparison. `λ̃`, `λ*`, the raw `λ` and `origin_is_feasible` all go to the manifest (spec §3.6: no hidden scaling). BUILD_PLAN §1.7 records the decision. **Left open for M7**: `λ*` is a function of `w` (doubling every weight halves it), so the reweighting loop must choose — and record — whether λ stays frozen at its base-weight value or is re-resolved from the frozen final weights. 392 tests green; ruff + mypy --strict clean.
- 2026-07-13 — **M4 gate PASSED (math-critical).** Built `affine_geometry` (scaled coords, orthonormal basis by support LPs, feasible centre, deterministic span certificate) and grew `native_csc`/`highs_backend`/`config`/`provenance` to serve it. 442 tests green; ruff + mypy --strict clean. **The milestone's central finding is scientific: the sampling dimension is 46, not 55.** 61 of the 260 free reactions cannot carry flux at all — the model file leaves `l < u`, but mass balance pins them — so `n_free − rank(S) = 55` is only an upper bound. `d = 46` is confirmed by an **independent FVA+rank oracle that shares no code with the geometry**, which is the gate's load-bearing test. **And those 61 reactions were not bookkeeping: they were a landmine under M5.** A blocked reaction is an *exact* structural zero of the direction space, so a basis row of ~1e-15 there is pure noise; divided by a centre sitting ~1e-13 *outside* its own bound (also noise), it produced **a chord limit of order 0.03–0.5** — inside the legitimate chord. Measured, the chord through the centre came out `[−0.54, −0.39]`, *excluding `t = 0`*, and `line_geometry` rightly refused to sample it: **M5 could not have started.** Now projected out exactly, and the geometry proves its own centre samplable before shipping it. **The `/collab` review ran 6 rounds and was worth every one — it found a crash, a silently dropped dimension, a dual-side blind spot, an accumulating basis error, an unsound bound formula, and two test bugs, one of which made a test unable to fail.** Every counterexample was reproduced before being fixed. Four things it changed that I would have shipped wrong: (a) **the certificate's resolution is `√k`, not its largest width** — width is subadditive, so a direction tilted across all 214 probes hides a factor of 14.6 from each one individually; (b) **flatness cannot be certified from the primal width**, which is a *lower* bound and the wrong end of the interval — a solve that stops short of optimality reports the width too *small* and certifies a real dimension as flat, so flatness now rests on a **weak-duality** upper bound that assumes nothing of the returned point, not even feasibility; (c) **the same bound must be applied to every FVA range**, since a range read off the primal is a lower bound and "this reaction cannot move" is exactly the conclusion a lower bound cannot support; (d) **error was accumulating along the Gram-Schmidt chain** (each column inherits `‖S·diag(s)·B‖·‖BᵀΔx‖` from its predecessors — the worst column hit 8e-10 against a 1e-9 tolerance), and an attempt to fix it by re-probing made it *worse*, so the chain is now cut by projecting every candidate into the mass-balanced subspace before it can pollute the basis. The honest consequence, reported rather than hidden: **the dual bound cancels terms of size ~5e3, so evaluating it in float64 costs ~1e-9 — that is the floor on what the certificate can resolve**, orders coarser than the ~1e-13 the arithmetic appears to produce. Certified resolution: **2.78e-11 scaled = 5.6e-8 flux units**, outward-rounded. What it licenses is stated precisely and narrowly: *every exact-polytope direction has its component orthogonal to `range(B)` bounded in width by that resolution* — **not** "cannot under-count a dimension". Also settled: three tolerances describe the same polytope and must not contradict each other (`scale_floor ≥ blocked_tol/span_tol`; `‖r_blocked/s_blocked‖₂ ≤ span_tol`; SVD rank cutoff ≥ the LP's `feasibility_tol`) — the first of those was a real crash. **Next: M5** (math-critical — `/collab` review required at the gate). M5 inherits a centre that is exactly bound-feasible, chords that all contain `t = 0` (min length 0.018), and support points that span all 46 directions, so its covariance ridge cannot conceal a singular covariance.
- 2026-07-14 — **M5 gate PASSED (math-critical).** Built `rounding` (support-covariance Cholesky → `T = diag(s)·B·L`, ridge + escalation, per-coordinate precompute), `maxent_sampler` (β=0 coordinate hit-and-run, multi-chain, dispersed starts) and `diagnostics` (split-R̂, Geyer ESS, autocorrelation, feasibility). 569 tests green; ruff + mypy --strict clean. **Zero HiGHS solves after sampling starts, zero bound violations across 12000 genome-scale samples, and every lifted sample feasible in the *full* 773-reaction polytope** — the one check only the lift can fail. The load-bearing statistical test is the **2-simplex**, whose uniform law has marginal density `2(1−x)`: it is *not* uniform, so a sampler that quietly returned uniform marginals — the failure a box cannot detect — dies there. It also has a control that must fail (a KS test against the uniform CDF, p < 1e-12), so a passing test proves something. **Rounding earns its keep, measured:** the shortest chord at the centre goes 0.018 → 0.744 (41×) and the spread across axes 77× → 3.8×. And the division of labour is now explicit: `diag(s)` absorbs *axis-aligned* stretch (a 1000:1 box gives unrounded chords differing by 1.41, not 1000), while `L` fixes the *correlations* no diagonal matrix can see. **The `/collab` review ran 3 rounds and found six defects that 553 tests passed over — none corrupting the β=0 distribution, but three corrupting what we *believed* about it, which on a sampler is nearly as bad.** (a) *The Geyer ESS paired from the wrong lag.* Γ_m = ρ_{2m}+ρ_{2m+1} starts at **lag zero**; pairing from lag 1 sums identically **only if nothing is truncated**, and truncation is the whole method. On an antithetic AR(1) (ρ = −0.5) the correct Γ₀ = +0.50 says *keep going* while the offset first pair is −0.25 and says *stop at once* — so it reported ESS = N for a chain whose true ESS is **3N**. (b) *`is_feasible` ignored mass balance entirely*, so a chain that had walked off the steady-state manifold — the half of `P`'s definition the entire affine geometry exists to enforce — reported `True`. (c) *The stored flux was the incremental cache*, so `to_flux(coordinates) != fluxes`, and the drift was measured **only at refresh instants** — not a bound on anything, since drift can peak and cancel *between* refreshes and a long `refresh_interval` would report a serene 0.0 having measured nothing. (d) *Nothing checked that `T` has full column rank*, the identity that licenses any ridge; **a `T` that quietly loses a column produces no bad numbers, only absent ones** — the chain samples a lower-dimensional slice with every sample feasible and every chord positive. (e) *`@dataclass(frozen=True)` freezes the binding, not the buffer*, and the precompute holds **copies** of `T`'s columns — so an in-place write would have the chord and the flux disagree silently; fixing it exposed a second latent bug, that `np.ascontiguousarray` returns its argument *unchanged*, so freezing the centre without copying would have made `ReducedGeometry.center` read-only underneath its owner. (f) *`np.min(x, initial=0.0)` is not an empty-array guard* — `initial` is a **candidate** for a min, so `min_ess` reported **0** for a sample whose every entry was 8000. I contested one Codex claim and it conceded: the relative-residual floor is correct **where the noise exists and absent where it cannot be** — a sampled *flux* carries solver noise at the blocked reactions (one row divides a noise value by itself and reports exactly 1.0), a *direction* does not (`T`'s blocked rows are exactly 0.0), so the transform's check is unfloored while the flux check is floored. Also settled honestly: **in float64 the chain is not Markov in `y` alone** (its state is `(y, cache error, refresh phase)`), exact Gibbs invariance is claimed *only* in exact arithmetic, and a measured drift is **not** a bound on stationary-law error. **🔴 The scientific finding: this model mixes slowly and the defaults do not cover it.** `step_scale_ratio = 0.008`, and at 4×(3000+3000) sweeps R̂ = 1.08 with min ESS 34/12000; R̂ reaches 1.04 only at 8000+8000. ESS grows linearly and R̂ falls monotonically, so the chain is correct-but-slow, not stuck (no coordinate has zero within-chain variance at any length). The remedy is **measured, not hypothetical**: spec §17.4 pilot rounding — re-rounding from a β=0 pilot chain's own covariance instead of the support-LP vertices — improves cond(C) 1.56e4 → 5.14e3 and **ESS by 2.5×**. It stays deferred to M10 (it is a separate DAG stage and does not touch the target), but it is the lever if wall-clock binds. **Next: M6** (math-critical — `/collab` review required at the gate). M6 inherits a kernel that already accepts `beta`/`objective`/`energy_scale` and *refuses* β>0 without them; it must supply the reduced-coordinate `L1Objective`, `s_J`, the ladder and the traces.
- 2026-07-14 — **M6 gate PASSED (math-critical).** Built `lower_objective`/`ReducedObjective` (the objective lowered onto the reduced polytope, carrying the fixed reactions' μ/C constants separately), `choose_energy_scale` (`s_J` per spec §22.2), and `run_ladder`/`ObjectiveTrace`/`MonotonicityReport` in the sampler. 696 tests green; ruff + mypy --strict clean. **The kernel is unchanged**: at β>0 the only difference is that `sample_line` builds M2's piecewise-exponential conditional instead of drawing uniformly, and every word of the §1.6.1 invariance argument survives, because it never mentioned the conditional's *shape* — only that it is exact. M6 supplies inputs, not machinery. Three deliberate deviations from the spec: (a) **`J` is not maintained incrementally** (§1.3 step 4 suggests it) — the kernel rebuilds every slope from `v` on the spot and depends on `J` only through peak-relative heights, so a running `J` would be a second cache to drift and reconcile, bought with nothing; traces are recomputed **exactly** from the stored fluxes; (b) the lowered objective is `J` **up to an additive constant**, which is not a defect but the same fact that keeps `J*` out of the kernel — the constant provably cancels from `p(t)` and must never reach a probability; (c) the near-zero counts are taken over the **movable** reactions, because counting all 260 free ones returns *exactly 61.0 at every β* — the FVA-blocked set, pure geometry masquerading as a sparsity signal. **The statistical gate is the milestone's real work**: an asymmetric truncated Laplace with an interior bend and 3:1 slopes (the first target in the package where `build_piecewise_j`, the segment log-masses and the categorical choice must all be right at once), a coupled `(1−x)·e^{γx}` simplex marginal where one factor comes from the *geometry* and one from the *objective*, a truncated exponential with no breakpoints at all, a β=1000 stress, and a **reduced-coordinate quadrature cross-check** that evaluates `J` straight from its definition and never touches the piecewise machinery — plus a *failing control* for every one of them. **🔴 The scientific finding: the engine is validated but the β-scale is not calibrated.** `s_J = 31.3` is read off M4's support-LP **vertices**, where the L1 cost is enormous, while the chain lives in the interior with `sd(J) = 2.6` — so `s_J` is 12× the range actually explored, `dE_β[J]/dβ = Var/s_J` is only 0.22 per unit β, and **β = 16 (the top of spec §22.1's own ladder) closes just 13% of the gap to `J*`.** Mean `J` rises 3.14 (6.9σ, monotone, R̂(J) ≤ 1.07) against a linear-response prediction of 3.44 — the agreement *pins the magnitude of κ*, not merely its sign — so the sampler is exactly right and the ladder is weak. Spec §22.2 already names the remedy ("support **or pilot** points"): **M10's pilot-based `s_J` is now a prerequisite** for presenting the ladder as spanning neutral-to-strongly-selected regimes (BUILD_PLAN §2.1). **The `/collab` review ran 6 rounds and found 12 defects — and by round 5 they were visibly one bug wearing twelve hats: *two artifacts that were never computed against each other, silently joined*.** A `ReducedObjective` is indices and weights; a `ReducedPolytope` is a matrix and bounds; an index is just an integer. So a mismatched pair is not *detectable* — it is **computable**, and computes confidently: the chain tilts by whatever reactions the objective names, `evaluate_many` reports *those same reactions* as μ and C, and the trace of `J` **rises monotonically with β exactly as the theorem demands**, because the chain really is maximizing the thing the trace measures. Every diagnostic agrees and every one describes the wrong model. Each round Codex named one more unguarded join and each time I patched *that join* — which was the mistake. The fix is an **invariant**: `ReducedPolytope.content_key()` (hashing `biomass_full_index` — the *reaction*, not its reduced coordinate, which is `None` for every fixed-biomass model and collapses them all together), carried by every downstream artifact, checked by `check_compatible` at **every** public join, where it was previously checked at none. Also caught: the `s_J` floor was `1e-9·max(1,|J*|)` — **not invariant to an additive constant of `J`**, so shifting `J` by +1e16 turned a healthy `s_J = 12` into a fallback and made every rung 12× hotter (the M2 delta-7 bug relocated to the calibration layer; the floor is now the float64 *resolution of the subtraction*, 64 ULPs); the degenerate-range fallback was **silent**, and spec §22.2's word is "**declared**" — a library default is not a declaration, so it now **raises**; the MC standard error paired the Geyer ESS with the *pooled* variance instead of the `var⁺` the ESS was built from, under-reporting the error by √2 **exactly when the chains disagree**; `monotonicity()` would have read a NaN as the most monotone ladder imaginable (`max(-inf, nan) == -inf` — the same trap as M5's `np.min(x, initial=0.0)`); and **my own regression test for the `s_J` floor could not fail on the bug it existed to catch** (the M4 lesson, repeated: the +1e6 shift left the old floor 1000× *below* the range). I contested three points and won them (Codex's NaN trigger raises earlier than he thought; the `2**53` drift example is unreachable under finite bounds; and the inner-loop primitives keep their invariant **by construction** at `CoordinatePrecompute.build`, which is where BUILD_PLAN §1.3 requires it, not on every step). One finding is **out of scope and recorded for M8**: `build_canonical_model` hashes a `source_path` against a separately supplied cobra model without checking they correspond, so a model mutated in memory can be stamped with another file's L0 cache identity. **Next: M7** (math-critical — `/collab` review required). M7 inherits the open M3 decision: `λ*` depends on `w`, so λ either stays frozen at its base-weight value or is re-resolved from the frozen final weights — it must be *chosen* and *recorded*, because it moves `J`.
- 2026-07-16 — **M7 gate PASSED (math-critical).** Built `reweighting.py` (`reweight_objective`, `ReweightingReport`/`ReweightingStep`, `update_weights`) — spec §13's iterative reweighted-L1 run to a **weight fixed point** and then frozen. 733 tests green; ruff + mypy --strict clean. **On the example model at λ̃ = 0.25 it sheds 134 → 131 active reactions, the frozen objective flows through the whole sampler with zero HiGHS solves after the freeze, and every tilted sample is feasible in the full 773-reaction polytope.** **The M3 fork is settled by measurement, not preference: λ is re-resolved every iteration (`λ_k = λ̃·λ*(w_k)`).** `λ*` is a function of `w`, and one step moves it 1.9e-3 → ~4e2 (default clip) because `C_w` changes *units* (a sum of absolute fluxes becomes very nearly a count of active reactions); a **frozen** λ collapses the effective pressure `λ/λ*(w)` from 0.5 to ~4e-6 **and crashes M3's `z == |v|` gate by iteration 2** (deviation 25, both measured). Re-resolving keeps `λ̃` meaning the same selection pressure across the loop and the batch, and makes the median renormalization a mathematical **no-op** (`w → cw ⇒ λ* → λ*/c ⇒ λw` invariant), which is why it is a conditioning step, not a modelling one. **Two silent-degeneration traps are now reported, not hidden:** a too-tight clip ceiling (below the `|v| ≈ 1e-3` "nearly off" band) turns reweighting back into plain L1 — measured, [1e-2,1e2] sheds 0, [1e-3,1e3] sheds 3 — surfaced by `support_unchanged`/`n_turned_off`/`n_turned_on`; and the weights are frozen **physically read-only** with the reweighter and sampler **structurally unable to import each other**, so a weight can never move mid-chain. **The `/collab` review ran 5 rounds (converged AGREE) and its through-line is the M6 disease with fresh fuel — two objectives on one polytope, whose `s_J` differ 100× on the toy while sharing a `polytope_key`.** Codex found five real defects, all fixed: (1) **convergence tested the fluxes, not the weights** — a global relative `max|Δv|` is dominated by a large flux and blind to the small sparsity-critical one whose weight is still halving, so the loop could freeze weights one stale step short of the fixed point; the stop test is now a per-reaction relative **weight** change; (2) **`n_shed` was net-only** and blind to active-set *replacement*; (3) **`LPOptimum` had no `polytope_key`** — `objective_key` hashes the objective's params, not the polytope's bounds, so two polytopes differing only in bounds hash identically and `J*(A) − Q(J_B(W))` passed every check; (4) **the warm-up array was unkeyed**, the third input to the `s_J` subtraction, so `choose_energy_scale` now requires a `warmup_polytope_key`; (5) **the clip ratio was unbounded**, and after median normalization the smallest weight is bounded by the *ratio* not `clip_min`, so it could underflow the fixed-point metric. Codex's first round ran in a **broken sandbox** (it saw the pre-M7 branch), so every line-level claim was verified against the real code before acting — its `with_weights(view)` freeze attack was **refuted** at runtime (all `_frozen` callers pass owned copies). I **held one point to consensus**: `optimum_coordinates` is a feasibility-checked *start hint* that enters only the initial state and cannot change the invariant target — Codex conceded (round 5), and the boundary is documented rather than papered over with a key that would imply it is load-bearing. BUILD_PLAN §§1.6.5, 1.7 updated; `.collab/specs/collab-outcome.md` § M7 records all 5 rounds. **Next: M8** (not math-critical — no `/collab` gate). Fix the M8-scoped L0 key defect (`build_canonical_model`) first.
- 2026-07-16 — **M8 gate PASSED.** Built the production layer — `output.py` (crash-safe writes: temp+fsync+atomic-rename, staged-directory publish with a `COMPLETE` marker written last, validated `.npy` persistence with a per-array sha256, and the three §1.3 storage modes), `cache.py` (a **layer-generic content-addressed store** with an atomic-`mkdir` writer claim, wait-for-`COMPLETE`, stale-claim steal, and on-load hash validation), `batch.py` (the models-manifest runner + one global `spawn` process pool over `(model,β,chain)`), `features.py` (per-model flux features + cross-model aggregation), and the M8 sections of `diagnostics.py` (the feasibility/objective/mcmc/geometry/solver JSON) and `cli.py` (`maxent solve-lp | build-geometry | sample | batch | diagnose`). 812 tests green (79 new); ruff + mypy --strict clean. **The milestone's opening move was the L0 key fix, and it set the pattern for everything after it: identity is a fingerprint of content, never a proxy that can drift.** `build_canonical_model` used to hash `source_path` while freezing a *separately supplied* model, so a model mutated in memory could be stamped with an unrelated file's cache identity; the L0 key is now `content_key(model_id, polytope.content_key(), exchange_mask, cobra+parser versions)`, and the file hash survives only as recorded provenance on the trusted `load_canonical_model` path. The same split reappears in the cache (a cheap *inputs* lookup key, an authoritative *content* hash checked on load) and would have reappeared in a naïve geometry cache — `RoundedTransform.from_bundle` **rebuilds** the per-coordinate precompute from `T` and the bounds and re-checks the reconstructed transform's `content_key`, so a cached transform is exactly as trustworthy as a freshly built one and a wrong-polytope reconstruction is refused (the M6 "two artifacts that never met" bug, blocked at the read boundary too). **The load-bearing engineering result: execution mode does not touch the numbers.** Serial and the process pool produce **byte-identical fluxes** because every chain's RNG is keyed on `(model_id, "sample", β_index, chain_index)`, never on a dispatch position — which is also what makes restart per-unit (a killed batch resumes only the units missing a `COMPLETE` marker; verified by mtime that the survivors are never rewritten and by bit-identity that the lost one comes back the same). Workers import `maxent_sampler`/`output`/`rounding` and **never cobra or HiGHS** (asserted at import), the parent does all parsing + LP work and ships frozen pickled arrays, and the sampling loop makes **zero HiGHS solves** (asserted against the process-global counter). A failed strain is recorded and skipped rather than fatal, and cross-model aggregation reads only per-model artifacts, so a **partial batch still yields valid tables** — tested with two strains, one deliberately broken. Design decisions recorded: the cache is layer-generic and only the **expensive, β-independent geometry (L3)** is wired to disk (L0/L1/L2 recompute in parse+reduce+a-few-LPs; wiring L2 is a mechanical extension using the same store), `write_json` allows non-finite tokens because diagnostics legitimately carry `inf` (a `blocked_separation` of ∞ when a model has no blocked reactions) while *array* files stay held to a finite bar by `load_array`, and pathway features are deferred (they need subsystem annotations the example models do not carry). BUILD_PLAN §1.1 updated (L0 content-addressed); no `/collab` (not math-critical). **Next: M9** — the benchmark suite, the worker-count sweep {1,2,4,7,14}, allocation/sort profiling, and validating the `reduced` storage mode at genome scale.
- 2026-07-16 — **M9 gate PASSED — v1 (M0–M9) COMPLETE.** Built `benchmark.py` (new module, not in spec §6 — like `provenance`, it earned its place: the gate asks for a *report*, and a report that only runs inside a test cannot be regenerated on a new machine or strain) + the `maxent benchmark` CLI + `tests/performance/` (the M0 placeholder was still empty). 847 tests green (35 new); ruff + mypy --strict clean. Report: [benchmarks/M9_REPORT.md](benchmarks/M9_REPORT.md). **Three measurement decisions are load-bearing and each exists because the naive version reports a number that means something else:** the sweep rate is a **slope** of two schedules (a `total/elapsed` ratio blends in the per-chain fixed cost and would *rise* with the schedule it was measured at); every stage reports its **median plus raw repeats** (a mean over three runs on a Jetson is one thermal event from fiction); and the LP stages are split **cold from warm** (2.9 ms → **1.08 ms**, which is what makes the geometry's ~1100 LPs affordable — M3's claim, now quantified). **🔴 The milestone's first real act was to fail.** The worker sweep would not run: both strains died with `RoundingError: ‖S·T‖ relative … above span_tol`. **M5's mass-balance gate rejects a perfectly samplable genome-scale geometry on 8 of 24 RNG streams — and since `model_id` keys the RNG, a *label* decided whether a model could be sampled at all.** The signature that exposed it is worth memorizing: **the *absolute* residual is constant to 1.8× across streams while the *relative* one swings 373×** — when a ratio is unstable and its numerator is not, the denominator is wrong. Codex's own discriminator settled the mechanism: a log-log fit of residual against row scale over 61009 (col,row) pairs has **slope +0.165**, not the **+1** a locally-generated error requires, so the residual is an absolute floor inherited from the basis construction and the gate was dividing a fixed ~1e-13 by a per-row scale as small as 1e-5 — **the M4 lesson ("never divide by a small number that is noise") one module further on**. M5's reassurance that it "passes on its own merits (3.5e-10 vs 1e-9)" was one draw from a distribution whose 79th percentile crosses the bar. Also found: **the code never implemented its own documentation** — `rounding.py:156` documents a per-column ratio of norms, `:788` computes a max of per-(col,row) ratios; five orders apart. **The `/collab` review (2 rounds, converged) is the reason the fix is right, and it began by destroying the fix I proposed.** Codex's counterexample: `S=[[1,-1,0],[0,0,1]]`, `|v₁|,|v₂| ≤ 1e12`, `|v₃| ≤ 1`, `T_k=(1,1,1e-10)` — the per-column formula reports `5e-11` and **passes**, while `v₃`'s bound lets the chord reach `|y| ~ 1e10` so `v₃` hits **1.0**: a mass-balance violation of order 1 with every reaction bound satisfied. It killed my cheap `ρ_k` box bound too (`Y = {|y₁|,|y₂| ≤ 1, |y₁−y₂| ≤ δ}`, `E_i = (1,−1)`: box says 2, truth is δ — `Y` is coupled, not a box). I conceded 4 points, Codex conceded 1 (its error model, on my slope evidence), and **it held one I had to accept**: `r/q` is not meaningless, it is exactly the Oettli–Prager componentwise backward error — the smallest relative perturbation of `S_i` making the equation hold — so the honest statement is that it is a *structural* quantity and the wrong thing to **gate** on, not a number describing nothing. **The gate is now `certify_reachable_mass_balance`**: 2 LPs per metabolite bounding the worst residual over the reachable set `Y`, against the **same `η=1e-9` contract `diagnostics.feasibility_report` already applies to emitted samples** — one declared definition of "mass balanced", proved a priori and checked a posteriori, rather than a second tolerance fitted to a measurement. Measured: **3.6e-11 … 5.1e-11, a 1.41× spread where the old gate swung 373×**, 20–28× inside the contract, **334 LPs / 0.5 s** (only 167 of 894 rows have `E_i` structurally nonzero), certified on every stream — **and it lands just above M5's independently measured 2.6e-11 emitted-sample residual, exactly as an upper bound on a superset must: two calculations sharing no code, agreeing.** `transform_mass_balance_error` survives as a **reported diagnostic that never raises**, because Codex showed it catches a corruption the certificate deliberately misses (`S=[1]`, `T=[δ]`, true dimension zero but `T` invents motion). **Two of M9's own defects were failures to heed this repo's own recorded lessons.** (a) *I certified from a primal reading* — M4 wrote "Never certify flatness from a primal reading; M5/M6 will face the same temptation", and M9 walked in: `objective_value` is a **lower** bound on a max, so a solve stopping short reports the reachable residual too *small*, unsound in the dangerous direction; the bound is now weak-duality (`max e·y ≤ Σ_j max(π_j lo_j, π_j hi_j) + Σ_k |d_k|·Ω_k`, valid for **any** `π`), with `Ω` from a **freshly recomputed** `T⁺` because a stored inverse does not get to vouch for the transform beside it. (b) *`benchmark_worker_sweep` reported a table of zeros* over a batch where every strain had failed — M8 makes a failed strain recorded-not-fatal, which is right for 46 organisms and wrong for a measurement; it now refuses. **A solver fact to keep: HiGHS drops a 1e-10 matrix coefficient sitting beside 1.0 coefficients** — reporting that row's activity as **0.0** where the truth is **133.3**, `max_primal_infeasibility = 0.0`, status optimal. Every tiny objective is normalized before it reaches the solver. **🔴 The performance finding contradicts the task's own hypothesis.** BUILD_PLAN asked for "breakpoint-sort profiling"; the chords carry a **median of 2 interior breakpoints (max 8)**, so `np.unique` (~12 µs of 104) is paying fixed NumPy call overhead, not sorting — you cannot optimize a sort of 2 elements. The real picture: a β>0 update costs ~104 µs, **`sample_line` is 89%** and `build_piecewise_j` alone **55%**; β>0 costs **7.98×** a β=0 sweep; and **`validate()` (11.8 µs) + `baseline` (6.5 µs) = ~18% of every update is work the draw never reads** (`baseline` is an absolute `J`, which M2 proved cancels out of `p(t)`). Deliberately **not** acted on: M9 is measure-and-assert, and `line_distribution` is the M2 math-critical kernel — recorded for M10 as the measured lever. **The worker sweep confirms M8's determinism through an instrument not built to check it: ESS(J) is identical to the last digit at 1, 2, 4, 7 and 14 workers (spread exactly 0)** — 14.77 ESS/wall-s at 14 workers (7.76×, 55% efficiency), and the decay is **Amdahl not contention** (parent's serial prepare = 4.0%, ceiling 24.9×, measured/predicted 98/95/88/84%); the lever is M8's L3 cache, since geometry is 1.17 s of the 2.29 s serial. `reduced` storage validated: cheapest to write (34.4 µs/sample) and **round-trips to 1.1e-13, *not* bit-exactly** — `_walk` lifts one row at a time (gemv) while `load_chain` lifts the whole block (gemm), and the test **localizes** it (the per-row lift is bit-identical) rather than hiding it behind a tolerance; byte-identity therefore holds **within** a storage mode, not across them. All five performance invariants hold, and two were built so they *can* fail: the chord's bar is 50 ns/reaction with **both endpoints measured first** (vectorized **7.6**, an interpreted loop **710** — a 93× gap), and the reconstruction count is asserted **differentially** so `dispersed_start`'s variable retries cannot mask it. **Next: M10.** Its first two items are now prerequisites rather than extensions — pilot-based `s_J` (without it the β axis does not mean what a reader assumes) and pilot rerounding (2.5× ESS). Then the **span certificate's own RNG-marginal gate** (~1–2 of 20 streams raise "not exhaustive"; same shape as §1.4.2, undiagnosed, deliberately untouched by M9) and the kernel's 18%.
- 2026-07-16 — **M10.1 gate PASSED — pilot rerounding + pilot-based `s_J`.** Built `calibration.py` (the DAG: bootstrap `T₀` → geometry pilot → `T₁` → scale pilot → `σ̂₀`, each artifact frozen before the next reads it), `rounding.reround_transform`, and `sparse_objective.pilot_energy_scale`/`PilotScaleReport`. 884 tests green (37 new); ruff + mypy --strict clean. **The milestone's first act was to falsify its own premise.** M6 recorded "pilot-based `s_J`" as a **prerequisite** and named the cure — spec §22.2's "support **or pilot** points" — with a magnitude, "~12× harder". I measured it before building: **the diagnosis was right and all three parts of the cure were wrong.** Swapping the point set *inside §22.2's formula* moves `s_J` 32.5 → 25.4 — **1.28×, not 12×** — because the `J*` anchor dominates; β to close the gap falls 117 → 91 against a ladder that tops out at **16**. **M6's "12×" is `32.5/2.44`: a ratio between an anchored *range* and a *spread*, two different quantities.** A prerequisite had been recorded, and a milestone gated on it, on arithmetic nobody had done. *A deferred remedy is a hypothesis, not a plan.* **The fix leaves the formula: `energy_scale="pilot_sd"`, `s_J = σ̂₀` (new mode, additive — `warmup_range` keeps its semantics and v1's results keep their label).** The *identical* ladder now closes **75.8%** of the gap at β=16 (E[J] −12.18 → **+4.24**, monotone, R̂ ≤ 1.06) where `warmup_range` closed **13%**; re-rounding (spec §17.4) lands beside it at cond(C_q) **1.54e4 → 5.36e3** (2.87×), step_scale_ratio 0.0081 → 0.0137, reproducing M5's independently measured 2.5×-ESS lever. **The `/collab` review ran 4 rounds (converged AGREE) and its whole value was killing my overclaims — Codex's verdict opened at DISAGREE against my *arguments* while its own recommendation was my candidate.** (a) *"β is Fisher–Rao arc length from the neutral ensemble"* — **false at finite β**: `ℓ(β) = ∫₀^β √(Var_t(J))/σ₀ dt` equals β only infinitesimally. A local property claimed globally. (b) *"the anchored coordinate governs no realized expectation"* — **exactly backwards, and this is the best argument in the exchange**: if the neutral deficit `X = J*−J` has a density of states `g(x) ~ C·x^{r−1}`, the tilted law is `e^{−κx}·g(x)`, so **measure-zero is precisely what *produces* the `x^{r−1}` power** and hence `r/κ`; therefore `1 − q(κ) ~ r/(κΔ₀)` and `κΔ₀` **does** govern gap closure in the sharp regime. Entropy *modifies* the coordinate, it does not defeat it — so E is natural in the *weak* regime and the anchored C in the *sharp* one, and **no scalar is universal**. (c) *"sd has one input"* — it removes the `J*` join only: **3 artifacts → 2**, not 1. (d) *"Var_β(J) shrinks"* — not a theorem; the sign is the tilted **third** central moment. (e) my candidate D was never a rival: **`(Q₉₅−Q₀₅)/3.289707 = 2.454`, 0.59% from the SD** — it only looked different because I never normalized it. I conceded all five. **The synthesis is better than either opening position: σ₀ sets the axis, Δ₀ is reported.** Because `1−q ~ r/(κΔ₀)`, publishing `q(β)`, `Δ₀`, `G = Δ₀/σ̂₀ = 9.03` ("headroom in neutral SDs") and `β·G` hands the reader the anchored coordinate as a **derived observable** — instead of baking it into the x-axis, where it would hide the very cross-strain quantity §1.1 exists to compare. **Two corrections I am most glad to have taken before writing them down.** *"Exact" belongs to the estimand, not the implementation*: `I₀ = 1` and `KL ≈ ½β²` hold for the **population** σ₀; the frozen plug-in gives `I₀ = σ₀²/σ̂₀²` — M6's "engine validated, scale not calibrated" one layer deeper, and I was about to write the overclaim into the docs. And my *"refuse when σ̂₀ is below numerical resolution"* **needs a predeclared implementation-level criterion or it quietly becomes the §1.4.2 noise-floor gate** — the repo's worst-ever defect re-entering through the door I opened; it now reuses M6's existing 64-ULP `ENERGY_SCALE_ULP_MARGIN`. So: **precision warns (2% target, never a gate — an unlucky pilot seed must not reject a correct run), validity refuses** (nonpositive/non-finite/below-resolution make the target *undefined*, a different failure from imprecise). `se(σ̂)/σ ≈ √(K−1)/(2√ESS_{(J−μ)²})` with **Pearson** kurtosis and the **centered-square** ESS — not the Gaussian `1/√(2·ESS_J)`, which fixes K=3 and reads the wrong series; measured, the two ESSs differ by **2.17×**. The estimand is **predeclared as the SD and never switched per strain** (R₉₀ = **1.015** measured, so J is nearly Gaussian here anyway) — switching on the diagnostics would forfeit `I₀ = 1` and make β mean different things in different strains. **Codex's `r_eff(κ) = κ·[J*−E_κ J] → c = d−f` is the best idea in the exchange and it is now a diagnostic — its small-κ expansion `κΔ₀ − κ²σ₀²` is confirmed to three digits** (predicted 2.20/4.27, measured **2.182/4.263**: a formula derived on paper by an independent model, landing on this sampler's output). Measured plateau **37.4 ± 1.9 (β=32) → 37.0 ± 3.6 (β=64)**, corroborated by `κ²Var = 38.6` — two instruments sharing no formula agreeing at **c ≈ 37–39, so the optimal face has dimension f ≈ 7–9** in a d=46 polytope (tentative, under-powered). 🔴 **Above β=64 the ladder measures its own mixing, not geometry**: R̂ 1.22 → 1.39 → 1.79 → **1.91**, ESS → **4**, and E[J] *falls* 8.6357 → 8.6109 from β=128 to 256 — which M6's theorem (`dE/dβ = Var/s_J ≥ 0`) proves is never physics. Codex's `J*`-indictment signature (linear drift, `r_eff` 44 → 91 as κ doubles) fires there and is **unattributable**, the diagnostic's precondition being a converged chain. **Practical rule: β = 16 is the working top rung at 4×(2000+2000).** **My own test found a real defect before the design could ship**: `run_chain` hardcoded `stage="sample"`, and since the two pilots are β=0 chains on the same model with the same chain indices, the *stage* is the only coordinate separating them — **they drew identical numbers**, and the independence that makes pilot-seed sensitivity attributable was a comment rather than a fact. `stage` is now a parameter. **Next: M10.2** — wire the DAG into `batch`/CLI. It is reachable via `calibration.calibrate` but not from the CLI, because `batch._load_or_build_geometry` returns a cached `RoundedTransform` with **no `ReducedGeometry`**, which `reround_transform` needs: that requires deciding whether the pilot and `T₁` join §1.1's 4-layer cache DAG as a new layer. A fork BUILD_PLAN does not settle, and deliberately **not** rushed at the end of this session — which is precisely the shape of the defects M4 and M9 recorded.
- 2026-07-16 — **M10.2a gate PASSED — the pilot DAG is wired into `batch`/CLI, and four artifacts were not functions of their keys.** 907 tests green (+23); ruff + mypy --strict clean. `gsmm-compiler maxent sample --set sampler.energy_scale=pilot_sd --set sampler.pilot_reround=true` now runs the DAG end-to-end. **The milestone's first act was to falsify its own framing — again.** This tracker recorded M10.2 as blocked on "a real fork BUILD_PLAN does not settle": the cache returns a `RoundedTransform` with no `ReducedGeometry`, so the pilot and `T₁` must "enter the 4-layer DAG as a new layer". **The arithmetic nobody had done says otherwise**: geometry is **1.168 s**, the two pilots are **19.202 s**, `reround_transform` is **9 ms** — so a layer for `T₁` would exist to avoid rebuilding a 1.17 s stage while costing 19.2 s to fill, **16.4× upside-down**. And the blocker was not a fork at all but **plan/code drift**: §1.1 has *always* said L3 holds "**B**, support_points, center, L, T, dimension, **span certificate**", while `to_bundle` held no `B`, no `s`, no certificate, and `ReducedGeometry` had **no serializer at all** — M9's "the code never implemented its own documentation", one layer up. *The M10.1 lesson repeating one milestone later, in this file's own prose: a recorded remedy is a hypothesis until someone does the arithmetic.* The rule that replaces it: **cache what is expensive, derive what is cheap, key everything** (BUILD_PLAN §1.6.7). **The through-line is §1.1's asymmetry — *a false miss only recomputes; a false hit corrupts* — which makes an incomplete key strictly worse than none** (absent means no cache; incomplete means a store that confidently returns the wrong bytes). Asking "is this artifact a function of its key?" of things this repo already had returned **no** four times, and **two are v1 defects M10 merely made reachable**. (a) 🔴 **M9's mass-balance gate was bypassable through the package's own cache-warming path** — it lived only in the `compute()` closure of `_load_or_build_geometry`, which runs **only on a miss**, so a hit read no certificate; and `maxent build-geometry --cache-dir` wrote its *own* bundle under `batch`'s key, omitted the certificate, and **stored it after printing REFUSED**. Warm, then sample: an uncertified transform, exit 0, every downstream check green. That gate cost a 2-round review whose first fix Codex's counterexample killed — and two CLI commands walked past it. Two writers of one schema is the defect; `build_l3_bundle` is now the one writer and raises rather than returning an uncertified bundle. (b) 🔴 **A `COMPLETE` marker named a chain, not an experiment** — §1.1 specified the sample key from the start and **nothing computed it**; `store_chain` recorded only `polytope_key`. A results tree reused after any change that moves the numbers resumed the units it had and sampled the rest **from a different law**: two experiments in one tree, stacked into one cross-model table, **every per-chain diagnostic green because each chain really is correct**. M10 forced it rather than created it — `T` and `s_J` were once pure functions of the polytope and config, and now descend from a pilot, so two runs of one unchanged config can honestly disagree. `sample_recipe_key` computes it; `_already_done` **refuses** rather than recomputing, because a results tree is the user's output, not a cache. (c) ⚠️ **The neutral pilot was objective-dependent and its docstring denied it** — `calibrate` fed both β=0 pilots `optimum_coordinates`, from the objective's own LP optimum, while `NeutralPilot` claimed "**objective-independent** … one neutral pilot serves every objective on a polytope" and hashed neither it nor the start. Measured, two pilots differing in *nothing else*: **identical `content_key`**, max |Δy| = 2.79, `T₁` cond 7198 vs 9663, `s_J` 2.6287 vs 2.4995. **Not bias** — both are honest draws from one β=0 law and the gap is Monte Carlo noise, and claiming bias would have been the overclaim; the defect is that **the artifact was not a function of its key**, so M7's two-objectives-on-one-polytope case takes the first hit and never knows. Codex's mechanism beat mine ("a different start"): the hint changes the support hull's **cardinality**, hence the **Dirichlet draw's dimension**, hence **RNG consumption on every later transition** — the streams *desynchronise*. Fixed **structurally**: `run_neutral_pilot` has no such parameter, because a defaulted `None` can be forgotten and an absent parameter cannot. M10.1 had shipped that hint with **zero test coverage** — removing it broke no test. (d) ⚠️ **`T₁` was sampled uncertified**, and must be certified **before the scale pilot**, which is itself a chain stepping in `T₁`'s frame — an uncertified `T₁` means σ̂₀ is read off off-manifold fluxes. The exact-arithmetic theorem does **not** transfer `T₀`'s certificate: `range(T₁) = range(T₀)` makes the *true* worst residual identical, but the certificate is a **numerical** bound recomputing `E = S·T₁` and `Ω` from a fresh `T₁⁺`. Measured: `T₁` certifies at **3.86e-11**, inside M9's independently measured `T₀` range of 3.6e-11 … 5.1e-11 — **two certificates, two matrices, no shared computation, agreeing where the theorem says they must**. **The criterion, stated once because getting it wrong is easy: an artifact key asks "are these bytes the same artifact?", *not* "is this the same distribution?"** M10.2 excluded `optimum_coordinates` from the sample recipe by importing M7's target-identity reasoning (§1.6.5) — **while having just fixed the identical defect for the pilots**. Codex's refutation is decisive and general: the recipe key already hashes `seed`, `chain_index`, `schedule` and `storage_mode`, **none of which define the stationary law**. Both keys are right; they answer different questions. `movable` is the one exclusion that survives (an exact function of a transform already hashed). **The `/collab` review ran 4 rounds and its shape is the second finding: a guard is only as total as its weakest entrance, and each repair had a smaller hole behind it.** Round 3 opened **DISAGREE on my implementation** and found a defect **I had just introduced** — `prepare_model` reported the L3 bundle's certificate, which is **`T₀`'s, while production sampled `T₁`**, in cache field-name form with the derived verdict lost: *a manifest describing an artifact that was not used* — this package's signature bug, committed by me, in the milestone about it. Then, in turn: **don't trust the claim** (`is_certified` is derived, so `to_cache` stores fields and the loader re-derives) → **the evidence was never checked** (`from_cache` checked only that fields were *present*, so `worst_absolute = −1` sails through `−1 ≤ 1e-9` and a **corrupted** certificate certified through the mechanism built to stop a **fabricated** one) → **the certificate chose its own bar** (`certify_reachable_mass_balance` accepts any positive `contract`, so `contract=1.0` yields a **truthful** `is_certified` that passes the gate — a proof of a different and useless proposition, no corruption involved; M9 settled there is **one** declared definition of mass-balanced, so the gate now tests `worst_absolute` against **the policy** and the certificate's `contract` is provenance) → **and gating an orchestrator does not gate its primitive** (`calibrate` took a required `bootstrap_certificate` while public `run_neutral_pilot` beside it still started the same chain uncertified; it takes one too). That is M2's "the first fix for a numerical bug is often itself buggy", generalized from arithmetic to authority. Codex also caught §1.1's own rule unapplied — `SAMPLER_IMPL_VERSION` is scoped to the *kernel* while `store_chain` decides the arrays, casts and manifest fields with **no version at all** (new `output.OUTPUT_IMPL_VERSION`), and confirmed the scope cut and the payload plan for M10.2b. **Honest scope, recorded rather than blurred**: none of this is adversary-proof — a caller who hand-builds a plausible certificate defeats any Python-level proof object — and the docstrings say so; it closes the repo's stated corruption model (accidental damage + ordinary API misuse). `ArtifactCache` still hashes every array and **trusts the meta**; that digest is deferred **by agreement** as an all-layer property, not an L3 one. Every one of the 23 new tests was verified to **fail on the bug it guards** by reverting each fix in turn. **Next: M10.2b** — cache the pilots per chain and dispatch them through M8's pool. Pure performance and measured: 19.2 s of *serial parent* work per model drops the Amdahl ceiling 24.9× → ~3.65×, and an uncached pilot means a restart re-runs it before resuming one chain.
- 2026-07-16 — **M10.2b gate PASSED — the pilots are content-addressed, and the gate runs *before* the dispatch.** 922 tests green (+15); ruff + mypy --strict clean. **Measured first, per this repo's own 3-for-3 rule, and every recorded premise held**: pilots **19.31 s** (recorded 19.2), geometry 1.17 s, reround 9 ms, payloads exactly the agreed 2.94 MB / 16.64 MB. Result: **`prepare_model` 23.08 s → 1.17 s warm (19.6×, 21.9 s of serial parent work removed)**, with `T₁`'s key and `s_J` **bit-identical** cold vs warm vs no-cache (`s_J = 2.520009578949248`), 19 MB stored against the 19.6 MB predicted. **The `/collab` ran 3 rounds and round 1 destroyed my position — the best outcome available.** I opposed the recorded payload split because it kills both tests that "prove the pilots are independent". Codex: `not np.allclose(a,b)` proves **non-identity, not independence** — the tests' names overclaimed — and *the property they name is not even true*, since `T₁` is derived from the geometry pilot, so the scale pilot depends on it **through its own frame**. What is independent is each pilot's **RNG stream given its inputs**; the direct evidence is the **spawn key**, which `run_chain` already records and `NeutralPilot` **discarded wholesale** — so BUILD_PLAN §1.2's "derive streams from semantic coordinates **and store the spawn keys**" was unmet, found while fixing another instance of the same drift. M10.2b stores them as a cache-hashed array and **recomputes** the expected keys on every construction: **M10.2a's bug (`stage` hardcoded to `"sample"`) would now raise on the first pilot ever built.** Codex then **talked me out of the flux fingerprint it had itself proposed** — a digest of the geometry pilot's *discarded* fluxes is an unrederivable assertion in trusted meta, and comparing two digests re-runs the proxy we had just rejected: **evidence you recompute is evidence; evidence you store and read back is a claim.** Structure settled: `PilotRecipe` (the key's inputs, computable *before* the artifact — one writer, since two writers of one key is M10.2a's defect) + `GeometryPilot`/`ScalePilot` with `STAGE` as a **ClassVar** and no `stage` parameter anywhere, so a class and its key cannot disagree. 🔴 **The diff's highest-risk line is the one the natural implementation gets wrong**: `get_or_compute(key, lambda: run_pilot(...))` leaves the gate inside `compute()`, **which runs only on a miss** — M10.2a's defect verbatim. Gate hoisted to the caller; **proved rather than asserted** by putting it back and watching `test_a_cached_pilot_still_refuses_an_uncertified_transform` fail with *DID NOT RAISE* while both miss-path gate tests stayed green. 🔴 **And then round 3 found the hole in that very repair** — the recorded lesson, verbatim, one milestone on. Hoisting the *certificate* left the **polytope relation** behind in `_run_pilot_chains`, miss-path only. I had probed for exactly this and my probe passed, because an *honest* wrong polytope changes the keys and is caught three other ways. Codex's attack works: `dataclasses.replace(transform, polytope_key=<a lie>)` — `RoundedTransform.content_key` hashes `geometry_key`/`transform`/`center`/`ridge` and **not the transform's own `polytope_key`**, so the lie keys identically, the certificate gate's two comparisons are both against unchanged values, and the pilot is served. **Executed: empty cache refuses, warm cache returns a pilot.** *A hit accepted what a miss refused, in the milestone about exactly that.* `require_pilot_inputs` is now the one place both paths ask: **hoisting one of two checks is how the first version closed an asymmetry while claiming to have closed the asymmetry.** Round 3 also refused three of my overclaims, all narrowed rather than defended: the **spawn-key guard** proves the four *semantic coordinates*, **not** the whole stream (`seed` is the `SeedSequence` entropy, absent from `spawn_key`, so a hardcoded-seed regression sails through — `run_chain` never records the entropy, so the guard cannot honestly reach further); **"`_frozen` is the only array constructor" was false** (it ran in the two *well-behaved* constructors while plain dataclass construction produced a mutable pilot — an invariant two callers agree to uphold is a convention, so `__post_init__` now normalizes and shape-checks the payload against the recipe's `n_chains × n_draws`, which `from_bundle` never did); and **the `IMPL_VERSION = 3` rationale was wrong** (`content_key` passes `feasibility_tol` as a named component, so v3 keys already differ, and no v2 pilot was ever stored — kept as bookkeeping with an honest reason, since *a version constant defended by a false argument is worse than one defended by none*). ⚠️ **Two defects found by building**: the pilots **ignored `geometry.feasibility_tol`** (silently using `run_chains`' 1e-9 default while production used the configured value) — the key was complete only *because* the tolerance was a constant, and honouring the config makes an unhashed tolerance a false-hit generator, so both halves had to land together; and **the log announced a 19.3 s pilot on a 40 ms cache hit**, a manifest describing work that did not happen, found by reading the CLI's own output. 🔴 **And a new lesson, sibling to M6's "12×"**: BUILD_PLAN §1.6.6 and three docstrings recorded `cond(C_q)` **5.36e3 (2.87×)**; the shipped code gives **5.97e3 (2.57×)** and has since M10.2a, because removing the start hint **changed every pilot's draws** — its own `CALIBRATION_IMPL_VERSION = 2` note *says so*, to justify the bump — and nobody re-measured what those draws produce. Confirmed: **with hint 5304, without 5969.** Corrected in place; **BUILD_PLAN §1.6.6b**: *a recorded measurement is a claim with a premise, and it expires silently when the premise moves. A version bump announcing "this changes every draw" is a bell that should ring for every derived number in the docs — it was rung and not heard, in the milestone about artifacts drifting from their keys.* **Next: M10.2c, and the tracker's own recorded remedy is the weaker one** — it named "two-phase pool dispatch" (parallelise a pilot's 4 chains: ≤4×, 4 of 14 workers busy), but **§1.2 already mandates the stronger fix and the code disagrees**: "process models so their per-model geometry can overlap the **sampling** of earlier models". The pool is global ✓; `run_batch` is `for spec in specs: _run_one_model(...)` and blocks on every future, so no overlap exists. Third time that pattern has held. Also measured and unrecorded: **`ArtifactCache` has exactly two live layers, `L3` and `pilot`** — L0/L1/L2 are described in its docstring and stored by nothing, and the `file_lookup` key this tracker describes does not exist, which is why warm `prepare_model`'s remaining **1.17 s is essentially all cobra parsing**: the DAG's dominant serial term is a stage the docs claim is cached.
- 2026-07-17 — **M10.2d gate PASSED — L0 is cached, and a warm run no longer imports the parser. Its CLI check then found a v1 defect that predates it.** 938 tests green (+13); ruff + mypy --strict clean. **Measured first, and the arithmetic set the scope**: warm `prepare_model` was 1.21 s and essentially all `load_canonical_model` — a stage `cache.py`'s docstring and this file both described as cached and nothing stored (M9's "the code never implemented its own documentation", a third time). §1.1 names a *four*-layer DAG, but measured warm `.reduce()` (L1) is **1 ms** and objective+LP (L2) is **45 ms** against `load_canonical_model`'s **1.157 s** — so keying them would be §1.6.7's "16.4× upside-down" mistake with new numbers. **L0 only**; three layers are live (`L0`, `L3`, `pilot`), and `GEOMETRY_CACHE_LAYER` was named so they are countable. Result: warm `prepare_model` **1.21 s → 0.645 s**, `T₁`/`s_J` bit-identical. 🔴 **The prize was bigger than the parse, and the key had to be designed for it**: `load_canonical_model` is 1.157 s cold and 0.52 s warm — the gap is cobra's own **0.65 s import, 54% of the cost** — so a cache that skipped the parse but still read `cobra.__version__` for its key would recover barely half of what it was built for. `provenance._installed_version` reads package **metadata** and `load_model` imports cobra lazily, so **a warm run never imports cobra at all** (pinned in a subprocess; the L0 hit is **4 ms**). **L0 needs two keys and that is not a hedge**: M8 made its identity content-addressed, and you cannot fingerprint a model's contents without parsing it — so `model_lookup_key` is a function of the *inputs* (`hash_file`: 1 ms) while `l0_key` stays the authority, **re-derived on every load**, which is also what makes it safe to put the reaction IDs in `meta` (which `ArtifactCache` does not hash). ⚠️ **The lookup key hashes the resolved source path, and that is not redundant with the sha256**: `build_canonical_model` falls back to `source.stem` when a model has no `id`, so two identical files under different names are two different `model_id`s — and `model_id` keys the RNG. 🔴 **Then the CLI check found the real thing, and it is a v1 defect I did not cause** (HEAD fails identically): **`maxent sample` fails from a clean cache under default threading.** The ambient BLAS thread count changes the **basis** — `OMP_NUM_THREADS=1` → `d35fe4fccf`, unset/4 → `970f8dddac` — under **one L3 key**, so *the L3 artifact is not a function of its key*. Support points are identical (HiGHS is pinned to `threads=1`); the basis is NumPy/BLAS, which reduces in a thread-dependent order. **Both bases are valid** (identical M4 span certificates, same d=46, same cond 1.537e4, both `T₀` certify) — but one yields a `T₁` whose `certify_reachable_mass_balance` LP returns **kUnknown**, so **the ambient environment decides whether a valid model can be sampled at all**: M9's own lesson ("a *label* decided whether a model could be sampled") with the environment as the label. **It fails closed** — the certificate refuses rather than sampling something wrong — so no incorrect numbers were ever produced. **Why nobody noticed: every recorded CLI verification, mine for M10.2b included, reused a cache warmed by a threads-pinned probe**, so this file's own "Verify current state" command fails from a clean state. 🔴 **I first recorded this as "§1.2 mandates the fix and the code disagrees — the fourth time today". That was WRONG, and `/collab` caught it (AGREE, 2 contested).** §1.2's thread rule is a sub-bullet of *"Sampling: process pool over (β, chain) units"* whose own parenthetical gives its reason — "the real oversubscription risk **in solver-free workers**" — and it is **implemented and works**: `run_batch` pins the env *before* creating the spawn pool, so each worker's freshly-imported NumPy inherits it. **There is no drift. There is a gap in the plan**: nothing ever required *parent-side geometry determinism*. Worker oversubscription (performance) and geometry reproducibility (correctness) are **two requirements sharing one mechanism**, and conflating them is why the second went unstated for ten milestones. **I pattern-matched a rule onto a case it does not cover, in the very session where that rule had paid off three times** — the repo's own recorded failure mode about confident prose, committed while recording it. (The one real §1.2 nit: `_limit_thread_env` uses `setdefault`, so it does not enforce 1 when the caller exported 4.) **Next: M10.2e** — Codex's design: keep the policies separate; scope a **forced** BLAS limit around L3 construction; **bump the L3 key** (or caches holding the ambient basis stay valid hits); record recipe key + content key + basis/`T₀` hashes + policy version + BLAS vendor/arch in the manifest (visibility *beside* elimination — it would have made "one recipe key, two content keys" visible immediately); and restate §1.1's promise as *within a declared numerical-runtime profile*, since cross-machine byte identity and cache sharing cannot both be had. The certify-kUnknown fragility is **recorded, not chased, by agreement**: pinning makes that basis unreachable by default and does not fix the coin flip.
- 2026-07-17 — **M10.2e gate PASSED — the L3 artifact is now a function of its key, and the standing blocker is cleared.** 954 tests green (+16); ruff + mypy --strict clean. **`maxent sample` completes from a clean cache under default threading** (4/4 units, `T₁` certified 3.87e-11) — the first time the suite and the CLI have both been green from a clean state since M10.2a. Full reasoning: **BUILD_PLAN §1.6.8**. **Measured before building, per this repo's own rule — and the measurement moved the design twice.** (1) 🔴 **The collab's scope was wrong in *both* directions.** It named the *basis* as the BLAS-sensitive artifact; measured, `build_transform` is sensitive **independently of the basis** (hold the basis fixed at `55d39f6b87` and `T₀` still moves: `8e587b6ad5` pinned vs `9d334b3f31` ambient), so scoping the basis alone would have left half the defect in place while announcing the geometry deterministic. Conversely the **sampler needs no scope at all**: freeze the geometry and `T₀` and the draws are bit-identical at 1 thread and at 14 (`2b13baec26`), its inner loop being chord arithmetic below any BLAS threading threshold. Three constructors, each verified individually rather than wrapped on suspicion. (2) **A runtime limit reproduces an env-pin bit-for-bit** (`55d39f6b87` both ways) — which is what made the *scoped* option real, rather than a library mutating its caller's `os.environ` at import (which cannot work anyway: BLAS reads those at load time). Implemented as `numerics.deterministic_blas`, **forced** (a caller exporting `OMP_NUM_THREADS=8` still gets the keyed basis) and **scoped** (the caller's process is untouched outside it) — both properties tested, because `_limit_thread_env`'s `setdefault` is right for a *performance* hint and wrong for a keyed artifact. **The two policies stay separate and separately named: two requirements that share a mechanism are still two requirements.** L3 key bumped via `DETERMINISM_POLICY_VERSION`, or caches already holding an ambient-thread basis stay valid hits and the fix reaches nothing that was warmed. **Visibility beside elimination**: `numerical_identity` in every bundle (recipe key, basis/`T₀`/support hashes, policy version, BLAS vendor/version/**architecture**/threads); the recipe key is a **gate** (a bundle must answer to the key it is stored under), a foreign runtime **warns** (refusing would make caches unshareable — the cost that ruled out keying the thread count). §1.1's promise restated: **within a declared numerical-runtime profile** a recipe key rebuilds deterministically; across profiles byte equality is not promised, and `s_J` is reproducible **in distribution**, not bit-for-bit. 🔴 **And the R̂ failure was never a threading problem — my own framing was wrong until I measured it.** Pinning the threads made `test_the_chains_mix_and_the_diagnostics_say_so` fail (R̂ 1.1654 vs 1.15), which reads like the fix breaking a test. Across **8 seeds** at the fixture's 1500 draws, R̂ spans **1.089–1.177** and min ESS **10.2–50.7**: the bars sat *inside* the distribution of valid runs, 2 of 8 seeds fail, and seed 0 — the fixture's own — fails **both** (its ESS failure hidden behind the R̂ assert that runs first). **The thread count was one way to toss a coin that seeds toss just as well.** Fixed the **schedule**, not the bar, because R̂ → 1 as the chain grows is a theorem: at 4000 draws R̂ is 1.033–1.059 and ESS 59.7–155.0 across 5 seeds — same bars, 2.5× and 3× margin. *A bar a valid input clears only 2 times in 3 is not a tolerance, it is a coin flip* — M9's lesson, third time. ⚠️ **Two of my own edits nearly repeated this package's signature bugs and were caught by writing them down.** The runtime profile is captured **inside** the policy's scope (`effective_runtime_profile` owns it): read outside, `num_threads` reports the ambient count, so the stored and compared profiles would disagree on **every hit** — a warning that always fires is a warning nobody reads, and a manifest describing a build that did not happen is M10.2b's own defect. And `test_a_poisoned_cache_entry_cannot_be_sampled` had to be **given a valid `numerical_identity`**: my new gate runs before the certificate is read, so the test would have passed while proving nothing — it would have gone on passing with `require_certified_transform` deleted from the hit path, the one thing it exists to catch. **The policy is free — it *pays*:** `build_geometry` **1.170 s pinned vs 1.488 s at 14 threads (21% faster)**, L3 total −0.317 s; a 260×46 Gram-Schmidt is far too small for 14 threads to repay dispatch overhead, so the nondeterminism bought nothing and cost 0.3 s. ⚠️ **Carried, not chased (agreed):** `certify_reachable_mass_balance` is **fragile** — the `T₁` that fails it is *better* conditioned than the one that passes (5352 vs 5969), so pinning the threads **hides** this rather than fixing it; any other model, seed or machine can still land on it. Also reconciled the checklist, which had drifted from this file's own session log: M10.2b/M10.2d passed and were still ⬜.
- 2026-07-17 — **M10.2c gate PASSED — `run_batch` overlaps, and the *default config* would have sent this milestone to the wrong lever.** 958 tests green (+4); ruff + mypy --strict clean; clean-state CLI 4/4 units, `s_J = 2.52001`. **For once this tracker's "§1.2 mandates it" claim was true** — a top-level *Batch scheduling* bullet against a `for spec in specs` loop that prepared, submitted and drained in one breath — **and it was still not sufficient reason to build it.** The arithmetic inverts between two configs: at `betas=(0.0,)` (the default) `P`=23.1 s vs `S`=1.3 s, so overlap is worth ~5% and the **pilots look like the target** (86.7% of `prepare_model`, 8 poolable chains walking one at a time while 13 cores idle — `run_chains`' own docstring says a pool "draws the *same numbers*"). **I believed that for an hour.** At the 8-rung ladder the package exists to run, `S` = **21.5 s** (β>0 units cost ~7× a β=0 unit — *my prediction of ~4 s was wrong and only the measurement caught it*), `P ≈ S`, and it reverses: **once prepare overlaps sampling the pilots are free**, so pooling them buys **0.7%** against a 23.2 s/model all-cores floor that overlap alone reaches. The recorded "two-phase pool dispatch is the **weaker** remedy" was **right for a reason it never stated**. Fix: a one-model lookahead (submit `i` → prepare `i+1` → drain `i`), one deep and never two. **A/B with both arms measured, M=3 cold: 131.6 s → 93.1 s = 1.41×** — which is **96% of the 1.47× M=3 allows**, not 73% of the 1.93× asymptote: `speedup = M(P+S)/(M·P+S)`, so quote the M, not the limit (§1.6.9). Draws bit-identical to the un-overlapped path. **The non-vacuity probe paid off immediately**: both overlap tests fail on the serial order, and my first lookahead-depth test **passed on the broken code** because two specs cannot distinguish depth-1 from depth-2 — it takes three. 🔴 **And the measurement found a v1 defect it did not cause: the span certificate refuses 12.5% of valid strains** (2 of 16 `model_id`s on one unchanged file; every run agrees `d=46`, `max_width≈1.85e-12`, then 1–2 probes of 214 are noise-swamped). Reproduces with no batch/pool/cache. *A 100-strain batch silently returns 88, and `metabolicSubcommunities` is that batch.* Deliberately not chased — one milestone at a time — but **promoted to Next action** over every remaining M10 extension (§1.6.10). **Next: the span certificate's RNG-marginal gate — and its remedy is a hypothesis until measured; do not widen the tolerance to get the verdict.**
- 2026-07-17 — **M11.0 gate PASSED — and the milestone's real finding is that v1 was measured on a sample of one.** 962 tests green (+4); ruff + mypy --strict clean. **`models/` holds one file and the batch is 40.** Swept `build-geometry` over every curated strain in `metabolicSubcommunities/method_3_curated`, default config, verified-intended inputs (the example model is **byte-identical** to the curated one; `ModelSpec` carries only path/biomass/id, so there is no medium to apply): **4 of 40 succeed.** 24 fail the blocked/moving split, 9 `kUnknown` on `flux_only`, 2 the span certificate, 1 `kUnknown` on `reachable_mass_balance`. **This file ranked the span certificate #1; it is the smallest of the four, and the two largest were recorded nowhere.** *Bifidobacterium adolescentis* is the **only anaerobe of the 40** — so d=46, 214 probes, "12.5% of strains", the worker sweep and §1.2's "at d≤55 sequential wins" are all one organism. This tracker diagnosed the gate-fragility *pattern* across four instances with real precision and then measured its *incidence* on n=1. **Nothing produced a wrong number: all four fail closed**, and the blocked/moving guard was *protecting* the distribution — cold FVA finds up to **8 more** blocked reactions, so warm was about to admit noise directions into the basis (§1.4.1's recorded disaster, where a ~1e-15 basis row divides into a chord limit of 0.03–0.5). **The mechanism, after 3 `/collab` rounds in which I conceded 13 points:** *primal quality is history-sensitive under warm starts, while these dual constructions stay sound independently of it — but their tightness varies, and must be judged by the resulting bound.* That is Codex's wording; my "chaotic primal, **good duals**" is falsified by this milestone's own FVA data. **Two necessary causes, and the second a design defect no solver fixes:** `dual_upper_bound` *deliberately* promises soundness for arbitrary duals, so a loose certificate is an **anticipated input** — but `blocked_reactions` reads `U > blocked_tol` as "moving" when it licenses only *"not certified blocked by this dual"*. **Both of my remedies were wrong and both died on evidence.** (a) Deriving `blocked_tol` from the rounding allowance, on my claim that the offending 3.38e-9 *was* that allowance: measured, it is **1.3% allowance, 98.7% raw bound** — the derived bar sits at 4.5e-11 and the reaction **still** classifies as moving. *It would have failed outright.* (b) Dropping `n_inconclusive == 0`: **unsound**, because `exhaustive` bounds the resolution **nowhere** — Codex's best catch, and the replacement (`resolution ≤ span_tol`) is *stronger* than today's rule and closes the marginal-truncation hole automatically. **I also committed this file's own recorded primal-lower-bound error** — arguing a reaction "does not move" from a negative primal width, *against a warning printed ten lines above the code I was reading*. M4 wrote it, M9 walked into it (§1.4.2), M11 makes three. **The paired census is what licenses the plan**: 40 models warm-vs-cold, **22 AMBIGUOUS→OK, 9 kUnknown→OK, 7 OK controls unchanged, 0 regressions** — so the mechanism explains **22 of 24**, not "all", and the residue is both *Hafnia alvei* strains (`n_blocked` identical warm and cold, `U ≈ 2e-9` vs a 1e-9 bar): **genuinely unresolved**, which is what the third state is for. **The acceptance criterion falls out of the disease**: it was *a gate whose verdict the seed decides*; after the fix the only refusals are two strains of one species, **deterministically** — a property of the model. **M11.0 itself was forced first, and Codex found why**: `geometry_cache_key` named NumPy and not HiGHS, though every L3 support point is an LP output. A bumped `BACKEND_IMPL_VERSION` was a **hit** that then died on the content key (§1.1 wants a miss), and the **HiGHS version was in neither identity**, so a `uv sync` silently served another solver's geometry. `highs_backend.solver_identity()` reads both from `importlib.metadata`, so the key never imports the solver — the M10.2d property the key exists to protect. **And the suite caught a bad test of mine**: it passed alone and failed in the suite because it asserted `'highspy' not in sys.modules` — global interpreter state, green or red by test *order*. M10.2d's own docstring already says why (*"In a subprocess, because a module another test already imported would make this pass for free"*); rewritten as a subprocess test and **proved non-vacuous by sabotage**. **Next: M11.1** — the third state + one bounded cold escalation, `/collab` first. ⚠️ **The census measures `blocked_reactions` only**: rounding, the pilot DAG and the sampler have **never run on an aerobe**, and every performance premise downstream of §1.2 is a claim about the one anaerobe.
- 2026-07-17 — **M11.1 gate PASSED (the disease), one residue documented (Codex would not let me call it closed).** 965 tests green; ruff + mypy --strict clean. `blocked_reactions` gets three states — certified BLOCKED (`U ≤ tol`, weak duality, no primal), **resolution-qualified** MOVING (`L > tol` strictly, `L = W − NOISE_SAFETY·2·admitted − eps·reach`, **never "certified"** because no Hoffman constant exists), and UNRESOLVED — with `U`/`L` stored **separately** and `L > U` a **loud** raise (the predecessor's `max(U,W)` could not *observe* a contradiction because it resolved it). A `kUnknown` warm solve yields no witness → UNRESOLVED → one **fully-cold** escalation, caught **caller-side** so `solve()` still refuses for everyone (`critical_l1_penalty` needs it). Census, build-geometry over all 40: **OK 4 → 20**. **`/collab` DISAGREED three times and each was load-bearing.** (1, design) my "certified MOVING" from a raw primal width was **unsound** — the code says so at its own noise bar — so it became resolution-qualified; my `max(U,W)` had to split; M11.1 needed its **own** `GEOMETRY_IMPL_VERSION` bump (2→3), not M11.0's backend bump. (2, the bug the census exposed) my first escalation shared one fresh instance for a reaction's `max` and `min`, so `min` warm-started off `max` — **one step of inherited history is still history** — and **10 of 40** falsely refused; a fresh instance **per solve** refuses **2**. The discriminator, not just a smaller number: *Hafnia* stays unresolved **both** ways (`U = 2.05e-9`, allowance `3e-11`, so the *dual bound itself* is above the bar), while *L. brevis* resolves the instant `min` stops inheriting `max`'s basis. (3, closing) **the stated gate "no reaction unresolved" is NOT met and I must not pretend it is**: *Hafnia*'s two reactions are a **repeatable certificate floor**, and `U > tol` proves *uncertified-blocked*, **not** proven-zero-width. What M11.1 actually fixed is the **RNG-marginal** refusal — `blocked_reactions` takes no seed, so its verdict is now a **structurally deterministic** function of the model, and the 24-strain seed lottery is gone. *Hafnia* is deferred (a stronger certificate, or documented `blocked_tol` guidance), not closed. **M11.1 also measured M11.2 into being**: the 8 `kUnknown@flux_only` + 4 span refusals are the *same* degradation in support-LP discovery and the span sweep, so M11.2 is the span gate (`resolution ≤ span_tol`) **and** a shared escalation mechanism — and whether the 8+4 share the cause is a measurement M11.2 makes first, not an assumption. **Next: M11.2**, `/collab` first. ⚠️ Geometry is one stage; rounding, the pilot DAG and the sampler have never run on an aerobe.
- 2026-07-18 — **M11.2 gate PASSED — span gate + a build-wide solve session; build-geometry 20 → 30 of 40, and a floor the sweep split in two.** 966 tests green; ruff + mypy --strict clean. **(A)** the span certificate's `exhaustive` is now `resolution ≤ span_tol`, not `n_inconclusive == 0` — the flatness claim rests only on each probe's rigorous `width_upper`, so a noise-swamped *primal* discovery signal is no reason to refuse. §1.6.10's decade-old open question is **answered: no** — an inconclusive probe is evidence about the solver's path, not the span (measured: the two failing directions are conclusive re-probed cold and after 30 unrelated solves; 46/46 constructed truncations were detected on *conclusive* probes; the signals are disjoint by ~5e4×). `strain_1`/`strain_11`, the tracker's original #1 defect for ten milestones, **now build** (resolution 2.7e-11 ≤ 1e-9). **(B)** a build-wide `_SolveSession` owns the LP instance: warm until the first `kUnknown`, cold-only after — fixing the leak Codex found, where M11.1's `warm=None` was local to `blocked_reactions` while `build_geometry` reused the same degraded program. Result: **`kUnknown@flux_only` 8 → 0**; the paired warm-vs-fresh measurement (required before building) confirmed each is warm-start history. **The `/collab` was design-review-first then a closing DISAGREE with four real discrepancies between my diff and the approved design, all fixed:** (1) `blocked_reactions` caught *every* `LPNotOptimalError`, not just `kUnknown` — an infeasible/unbounded status (a model verdict) would have been silently cold-retried; `_reraise_unless_kunknown` now re-raises all but `kUnknown`; (2) the cold pair bypassed the approved `solve_fresh_once`; (3) `degraded_at`/`n_cold_solves`/`n_lp_solves` counted different solve populations without saying so — `degraded_at` (a session index that read 0 when degradation was inside `blocked_reactions`) became `degraded: bool`, each counter now documents what it counts. 🔴 **(4) changed a conclusion.** I called the 2 span refusals "genuine, deterministic, confirmed cold"; Codex noted a cold re-sweep *keeps the RNG-discovered basis*, so a different `model_id` gives a different resolution — I had measured one seed each. **The 8-seed sweep split them: pumilus 8/8 refuse (a genuine √k floor, d=88); Liquorilactobacillus 3/8 pass (RNG-marginal, the √k certificate's basis-dependence, needs a tighter basis-independent certificate).** *The multi-seed measurement caught my overclaim, the same way it did for Hafnia — a bar a valid input clears only sometimes is not a floor until every seed agrees.* Both span residues deferred; the "samples valid to resolution R" contract is a separate milestone (a small orthogonal-width bound does not by itself bound the sampled law's error — a thin polytope's cross-section can vary strongly along retained directions, singular in TV against the full-dim target). **Next: M11.3** — the reachability certificate refuses on the one output (`row_duals`) it never reads (6 strains; measured CERTIFIED 27× inside contract from the discarded `kUnknown` duals); `/collab` (M9). ⚠️ Geometry is one stage; rounding, the pilot DAG and the sampler have never run on an aerobe.
- 2026-07-18 — **M11.3 gate PASSED — reachability's caller-specific dual-witness path; build-geometry 30 → 40 of 40.** 979 tests green (+8); ruff + mypy --strict clean. `/collab` design-review DISAGREE×3 (all adopted), closing AGREE. **The certificate refused on the one output it never reads**: `certify_reachable_mass_balance` uses only `row_duals`, but `_reachable_extreme` routed through `HighsLinearProgram.solve()`, which raises `LPNotOptimalError` on a `kUnknown` status *before* `getSolution()`. **Premise measured first, on all 6 failing strains (~2838 solves)**: the only non-optimal status is `kUnknown` (never `kUnbounded`/`kInfeasible`); `max_dual_infeasibility = 0.0` on every one; the discarded-dual bound agrees with a cold optimal re-solve to **7.8–9.0 digits**; the completed certificate is CERTIFIED **12–27× inside 1e-9**; and the `kUnknown` row is never the binding row — accepting its duals lets the loop *finish*, not change the verdict (weak duality is an upper bound for any finite duals). **Built**: `HighsLinearProgram.solve_dual_witness(*, accept)` returns a narrow `LPDualWitness` (not `LPSolution`, whose "holding one proves kOptimal" invariant stays true), reading the duals on a whitelisted status **without** loosening `solve()` (`sparse_objective.critical_l1_penalty` still needs its `LPNotOptimalError`); `_reachable_extreme` calls it with `{kOptimal, kUnknown}` (exact `.name` match, tokens validated); `ROUNDING_IMPL_VERSION 2 → 3` for the new `n_unknown_witnesses` telemetry field. **Codex's 3 (all adopted)**: the narrow witness type + `row_duals.shape`-only validation (it verified at the HiGHS 1.15.1 source that `HighsSolution::clear` can empty the dual vector); exact-name match, not the substring that also catches `kUnboundedOrInfeasible`; durable telemetry + version bump. **Deferred, conceded real**: the objective-normalization residual (`Σ|E_i − ‖E_i‖·unit|·Ω` + final outward rounding) is uncharged — but **dual-independent** (identical for kOptimal/kUnknown, orthogonal to this change), **pre-existing** (M9), and measured at **2.7e-25 / 4.2e-26** (~16 orders below the contract); its own small step. Integration test proven non-vacuous by sabotage (reverting the call site to `program.maximize` fails it with `LPNotOptimalError kUnknown`). 🔴 **The "40" honestly**: the **6 reachability fixes are durable/machine-independent**; the **4** previously-deferred strains (2 *Hafnia*, pumilus, Liquorilactobacillus) pass here as **basis-marginal** and can flip on another basis. ⚠️ **Geometry is still only the first stage** — rounding, the pilot DAG and the sampler have never run on an aerobe (M11.4, next).
- 2026-07-18 — **M11.4 end-to-end census — the pipeline is correct on aerobes; the cost is efficiency.** `/collab` design-review first (Codex DISAGREE, all 5 adopted): the load-bearing one — `maxent diagnose` reports R̂/ESS for **J only**, and a chain can mix in J while trapped along objective-neutral flux directions, so a naive census would declare success on a badly-mixed distribution. Built a flux-level harness (`benchmarks/census_diag.py`) for per-reaction R̂/ESS + the per-chain manifest diagnostics `diagnose` never surfaces. **Ran the full pipeline (rounding → pilots → sampler) on a 4-strain sentinel spread d=46/51/71/145, β=0 and the full 8-rung ladder. Findings — [benchmarks/M11_4_CENSUS.md](benchmarks/M11_4_CENSUS.md):** (1) **Validity holds everywhere** — bound viol 0, mass-bal ~1e-11 (≈100× inside contract), 0 degenerate steps, at every d and every β. `max_refresh_drift` (Codex's top blind spot — no stationary bound) stays ~1e-11 across all d and is **flat across β** (2.5e-11→2.0e-11), refuting the worry it grows with the tilt. (2) **Re-rounding preserves the target** — the β=0 T₀-vs-T₁ invariance oracle at d=145 passes (max |z| 2.20, 0% of 463 reactions beyond 3 MCSE). (3) **mean-J monotone** on both aerobe ladders (d=51 worst drop −2.1σ, d=145 +1.17σ). (4) **The real finding — mixing efficiency degrades ~4× with dimension** (median flux-ESS 270→200→63 for d=46/71/145 at fixed 2000 sweeps) **and with β** (lactis 239→90 as β 0→16). **J-only diagnostics hide it**: Rahnella β=0 R̂(J)=1.07 (looks marginal) while flux worst-R̂=1.48, median ESS 63 (not converged) — exactly the failure the design-review existed to catch. (5) **`s_J` precision degrades with d** (2.6%→3.1%→5.3%), and re-rounding's cond benefit is anaerobe-shaped (improves 2.57× at d=46, worsens 0.60× at d=145 — T₁ still certifies, carried by M11.3). **The under-mixing is a budget problem, not a pathology**: doubling Rahnella β=0 to 8k sweeps scaled ESS 3.19× (~linear, worst R̂ 1.48→1.08) — the signature of a chain exploring, not stuck. **Implication**: §1.2's efficiency premises (worker sweep, "d≤55 sequential wins") were tuned on d=46 and must be re-derived per dimension; the base schedule is under-powered on aerobes and needs to scale with d (a config default — M11.5), not a code fix. **No correctness defect surfaced.** Census is a 4-strain sentinel spread, not a 40-strain production census (that + a geometry-pilot covariance study + s_J under an independent pilot seed remain for M11.5).
- 2026-07-18 — **M11.5(a) — the dimension-scaled sampling schedule. 1005 tests green (+26); ruff + mypy --strict clean.** Followed the spec's ordering exactly: **MEASURE first, `/collab` think, then build.** **(1) Measured** — extended `benchmarks/census_diag.py` to the integrated autocorrelation time τ (worst/p90/median, in sweeps) and swept the production sampler across **9 strains d=34–145 × β∈{0,1,8,16}** (`benchmarks/M11_5_SCHEDULE_TAU.md`), a wider set than the 4 census sentinels *by design* — a rule fitted to 4 points is a guess. It **reproduces M11.4 exactly** on shared strains (β=0 median flux-ESS bifido 270 / pentosus 200 / Rahnella 63), then extends past them: at β=0, τ ∝ d^1.18 (median) / **d^1.63 (p90)** / d^2.23 (worst) — *the exponent is not a constant* — with ±1.5–2× strain-to-strain scatter at fixed d; **β inflates p90-τ up to 27×, and NOT as a function of d** (largest on the *smallest* model, bifido d=46 → 26.8×; Rahnella d=145 → only 4.0×); the worst coordinate is an estimator-noise floor (minESS 3–9 at β=16), so **p90 is the robust target, not worst, and not J** (J-only hid it). **(2) `/collab` think (3 rounds, AGREE)** on the fixed-vs-target-ESS-vs-doubling fork: **A (fixed d-power) refuted** by the unstable exponent + scatter + 27× β-inflation; **B (pilot target-ESS) is the right mechanism** — the pilot measures *this strain's* τ, killing the scatter and the fitted exponent; **C (doubling) deferred**. Codex opened DISAGREE on the *contract* twice while endorsing the *direction*, and every contested point sharpened it (the memory's "read the reasoning, not the verdict"): named it `pilot_ess` not `target_ess` (the β=0 pilot *predicts*, it does not *guarantee*); pass the **transform** to the resolver (the pilot stores fluxes + a transform *key*, not `T`, so it could not derive the movable mask) and *bind* `T.content_key()==scale_pilot.recipe.transform_key`; **corrected a false premise in the spec** — the restart guard does NOT resume a changed schedule (`_already_done` raises, no RNG checkpoint), so C is *re-run in a fresh dir*, not resume; add flux-level R̂ to `run_diagnostics` because J-only cannot verify flux mixing. **(3) Built** `schedule.resolve_schedule` — pure/deterministic; `fixed` (default) is the identity (**fixed-mode flux arrays sha256-identical to pre-change**); `pilot_ess` sizes `n_samples = ceil(target·τ_q/n_chains)` from the T₁ scale pilot's p90 flux τ, capped in **sweeps** (`//thin`), constant-coordinate τ=∞ retained then routed to the cap (`ceil(inf)` guarded). **THE TRAP closed**: the *resolved* config becomes `plan.sampler`, which `sample_recipe_key` hashes and the workers step under — a non-vacuous keying regression (rebuild the key from the raw sampler → different key) proves the resolved, not raw, value is keyed; `schedule_mode`/`target_ess` are policy-only and correctly *absent* from the key. `run_diagnostics` reports two separate booleans per rung — `ess_target_met` (achieved p10 flux-ESS ≥ target) and `convergence_diagnostic_passed` (flux max R̂ ≤ 1.05, nonfinite→fail); `target_verified` = both. Verified end-to-end: a `target_ess=60` run at d=51 verifies **β=0 (p10-ESS 116≥60)** and honestly flags **β=8 not verified (39<60)** — the measured β-inflation, reported not hidden. **Codex build-diff review: keying CONFIRMED correct, one honesty hole found & fixed** — `max_schedule_sweeps` was enforced in *retained-draw* units, so a `thin>1` run could spend up to `thin×` its declared *sweep* budget while reporting `cap_hit=false`; the cap is now a true sweep budget (`//thin`), validated `≥ n_samples·thin`, test-locked. Not a math gate (a longer chain samples the same π_β with more MC error). **Deferred**: option C doubling (β>0 handle), a dedicated flux pilot for non-`pilot_sd` configs, a burn-in policy. **Next: M11.5(b) release + (c) the full 40-strain production census.**

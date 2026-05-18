# Implementation Plan: Model Features

Covers 18 of the 20 features listed in `model_vs_implementation.md` — the gaps between the DSA-LSA paper's theoretical model and the current code. Two features (#12 tax application, #13 capital income tax) are skipped because the code's current implementation is more general than the paper's. Features are organized into 7 phases ordered by dependency, complexity, and risk.

**Key architectural constraints:**
- State space is currently `(T, n_a, n_y, n_y_last)` with `n_h=1` — no phase adds new state variables
- Both NumPy (`lifecycle_perfect_foresight.py`) and JAX (`lifecycle_jax.py`) backends must be updated in lockstep
- `OLGTransition` aggregation logic must be updated for any new output fields
- Tests must be added/updated for each feature; JAX cross-validation tests must continue to pass

---

## Progress

| Phase | Features | Status |
|-------|----------|--------|
| 1 | #11, #17, #20 | **Done** |
| 2 | #3+#5, #2, #16 | **Done** |
| 3 | #14, #15 | **Done** |
| 4 | #1, #6, #7 | **Done** |
| 5 | #4 | **Done** |
| 6 | #8, #10, #9 | **Done** |
| 7 | #18, #19 | **Done** |
| 8 | σ_α (post-baseline extension) | **Done (2026-05-08)** |
| 9 | Warm-glow bequest + initial wealth | **Planned (2026-05-11)** |

**Skipped:** #12 (tax application — keep code version), #13 (capital income tax — keep code version)
**Merged:** #3 (human capital) absorbed into #5 (age-dependent productivity) — no new state variable
**Post-baseline:** Phase 8 (σ_α permanent productivity fixed effect) is the first feature to add a new state variable; landed on main 2026-05-08 in merge `4a9e4aa`. Calibration result: ν=73.97, β=0.959 (vs 74.05/0.954 in the no-FE baseline); within-education `Var(log y)` rises from 0.112 to 0.169, matching the LIS-MD identifying moment. Wealth-Gini residual unchanged.

---

## Phase 1: Budget Constraint & Fiscal Fixes

Low-risk, independent changes to the budget constraint and fiscal accounting. No new state variables. Each can be implemented and tested independently.

### Feature #11 — Minimum pension floor

- [x] Implement
- [x] Test (NumPy)
- [x] Test (JAX cross-validation)

**Paper:** `PENS = max{ρ·ȳ, b_min}` with minimum pension floor `b_min`.
**Current:** `pension = replacement_rate × w_at_retirement × y_grid[i_y_last]`, no floor.

**Decision:** Keep the current `i_y_last`-based pension formula. Add minimum pension floor and career-average blending.

**Changes:**
- `LifecycleConfig`: Add `pension_min_floor` (float, default 0.0), `pension_avg_weight` (float, default 1.0).
- Modify `_compute_budget()`: pension base = `λ·κ(ret)·y_grid[i_y_last] + (1−λ)·mean_κ·mean_y_employed`, where `λ = pension_avg_weight`. Pension = `max(replacement · w_ret · pension_base, pension_min_floor)`. With `λ=1.0` (default), recovers the original last-state formula.
- `pension_avg_weight` is derived from `(1 − ρ^N)/(N·(1−ρ))` — the regression coefficient of career average on last state for an AR(1) with persistence ρ over N working periods.
- Apply the same formula in both solve and simulation, both NumPy and JAX backends.
- Files: `lifecycle_perfect_foresight.py`, `lifecycle_jax.py`, `calibrate.py` (auto-computes λ in `load_config`)

### ~~Feature #12 — Tax application~~ SKIPPED

Keep code's current sequential tax application (payroll tax first, then labor tax). More general than the paper's joint deduction.

### ~~Feature #13 — Capital income taxation~~ SKIPPED

Keep code's current explicit `τ_k` capital income tax. More general than the paper (which has no explicit `τ_k`). Setting `tau_k = 0` recovers the paper's formulation.

### Feature #17 — Government spending on goods (G_t)

- [x] Implement
- [x] Test

**Paper:** Explicit `G_t` in government budget constraint and resource constraint.
**Current:** No `G_t`.

**Changes:**
- `LifecycleConfig`: Add `govt_spending_path` (array of length T or scalar, default 0.0).
- `OLGTransition`: Add `G_t` to government budget accounting. In the resource constraint: `Y = C + I + G`. This affects the GE price-finding loop — government spending absorbs resources.
- This is primarily an `olg_transition.py` change. Individual lifecycle solve is unaffected (agents don't choose G).
- Files: `olg_transition.py`

### Feature #20 — Medical expenditure age-dependence

- [x] Implement
- [x] Test (NumPy)
- [x] Test (JAX cross-validation)

**Paper:** `m^need(j, s)` depends on age `j` and health `s`.
**Current:** With `n_h=1`, medical expenditure is a deterministic age-dependent level.

**Changes:**
- `LifecycleConfig`: `m_good` (base level), `m_age_profile` (array of length T, default all ones), `kappa` (government coverage share). Medical cost at age j: `m(j) = m_age_profile[j] * m_good`.
- Health states are shut down (`n_h=1`): no `P_h` transitions, no health-dependent productivity. `m_moderate`, `m_poor`, `h_moderate`, `h_poor` are unused.
- Modify `_compute_budget()` to use age-indexed medical costs.
- Files: `lifecycle_perfect_foresight.py`, `lifecycle_jax.py`

---

## Phase 2: Unified Productivity Process (Features #3 + #5)

### Features #3 & #5 — Age-dependent productivity transitions (replaces separate human capital state)

- [x] Implement config parameters
- [x] Implement `_income_process()` age/health variant
- [x] Implement solve changes (NumPy)
- [x] Implement solve changes (JAX einsum)
- [x] Implement simulation changes (both backends)
- [x] Test (NumPy)
- [x] Test (JAX cross-validation)

**Paper (Feature #5):** `P_z(z'|z, j, s)` depends on age and health.
**Paper (Feature #3):** Continuous human capital state `h` with `log h_{j+1} = log h_j + g_j + ε_j`.
**Current:** `P_y` is `(n_y, n_y)` — constant across ages and health states.

**Approach:** Instead of adding a separate human capital state variable (which would add a grid dimension), combine human capital dynamics and stochastic productivity into a single "labor market productivity" state with age-dependent transition matrices. The `y_grid` already represents productivity states; by making `P_y` vary by age, we capture:
- **Human capital accumulation:** Age-dependent mean/persistence (young workers have higher expected growth)

**No new state variable** — state space stays `(T, n_a, n_y, n_y_last)` with `n_h=1`.

**Changes:**

1. **`LifecycleConfig`:** Add per-education-type age-group parameters:
   - `rho_y_by_age`: dict mapping age groups to persistence values (e.g., `{'young': 0.95, 'middle': 0.97, 'old': 0.99}`)
   - `sigma_y_by_age`: dict mapping age groups to shock variances
   - `mu_y_by_age`: dict mapping age groups to mean growth (captures human capital accumulation)
   - Direct specification via `P_y_by_age_health` of shape `(T, 1, n_y, n_y)` for full flexibility (health dimension trivial with `n_h=1`)
   - Default: `None` (fall back to constant `P_y` for backward compatibility)

2. **`_income_process()` in `lifecycle_perfect_foresight.py`:**
   - When age-dependent params provided: construct `P_y` of shape `(T, 1, n_y, n_y)` using age-group Tauchen discretizations
   - Use 3 age groups (young < 40, middle 40-60, old 60+)
   - The `y_grid` stays the same (shared grid for all ages/health states) — only transition probabilities change
   - Store as `self.P_y` with shape `(T, 1, n_y, n_y)` when age-dependent, `(n_y, n_y)` when constant

3. **`_solve_period()` in `lifecycle_perfect_foresight.py` (line ~583):**
   - Change: `self.P_y[i_y, i_y_next]` → `self.P_y[t, i_h, i_y, i_y_next]` (when 4D)
   - Already inside `i_h` loop, `t` is the period parameter — trivial indexing change

4. **`solve_period_jax()` in `lifecycle_jax.py` (line ~189):**
   - `P_y_t` is the per-period slice, passed in the scan loop
   - With `n_h=1`, the health dimension is trivial

5. **`_simulate_sequential()` (line ~811) and `_agent_step_jax()` (line ~468):**
   - Change: `P_y[i_y, :]` → `P_y[t, i_h, i_y, :]`
   - Both `t` (lifecycle_age) and `i_h` are known at the sampling point

6. **`_simulate_sequential()` initial distribution (line ~706):**
   - Compute stationary distribution from `P_y[0, 0, :, :]` (age 0) instead of constant `P_y`

7. **OLG batched calls in `olg_transition.py`:**
   - `P_y` shape change flows through — still shared across cohorts within education type, just larger array

- Files: `lifecycle_perfect_foresight.py`, `lifecycle_jax.py`, `olg_transition.py`

### Feature #2 — Survival risk (stochastic mortality)

- [x] Implement config + solve
- [x] Implement simulation (mortality draws, bequest tracking)
- [x] Implement OLG aggregation (mortality-weighted cohort sizes)
- [x] Test (NumPy)
- [x] Test (JAX cross-validation)

**Paper:** `β · π(j) · E[V_{j+1}]` with age-dependent survival probabilities.
**Current:** Deterministic survival (all agents live T periods).

**Changes:**
- `LifecycleConfig`: Add `survival_probs` — array of shape `(T,)` or `(T, 1)` with `π(j) ∈ [0, 1]`. Default: all 1.0 (deterministic survival, backwards compatible).
- Modify backward induction: multiply continuation value by `π(j)`. In terminal period, unchanged.
- Modify simulation: at each period, draw survival shock. Dead agents exit the simulation. Track accidental bequests (assets of deceased).
- Modify aggregation in `OLGTransition`: account for age-varying cohort sizes due to mortality. Weight agents by survival probability in cross-sectional aggregation.
- **Important:** This changes the effective discount factor from `β` to `β · π(j)`, which will affect calibrated `β`.
- Files: `lifecycle_perfect_foresight.py`, `lifecycle_jax.py`, `olg_transition.py`

### Feature #16 — Bequest taxation

- [x] Implement (config param `tau_beq` added)
- [x] Test

**Depends on:** Feature #2 (survival risk).

**Paper:** `τ^beq` tax on assets of deceased, redistributed lump-sum.
**Current:** No mortality, no bequests.

**Changes:**
- `LifecycleConfig`: Add `tau_beq` (float, default 0.0).
- `OLGTransition`: After simulation, compute total accidental bequests, apply `τ^beq`, redistribute as lump-sum transfer to living agents. Add to government revenue accounting.
- Files: `olg_transition.py` primarily

---

## Phase 3: Tax & Transfer System

### Feature #14 — Progressive taxation

- [x] Implement
- [x] Test (NumPy)
- [x] Test (JAX cross-validation)

**Paper:** `τ^l(y) = 1 - κ · y^{-η}` (HSV functional form).

**Changes:**
- `LifecycleConfig`: Add `tax_progressive` (bool, default False), `tax_kappa` (float), `tax_eta` (float).
- When `tax_progressive=True`, replace flat `tau_l * income` with `income - kappa * income^(1-eta)` (HSV schedule). When False, use existing flat rate.
- Modify `_compute_budget()` to use progressive schedule.
- Files: `lifecycle_perfect_foresight.py`, `lifecycle_jax.py`

### Feature #15 — Means-tested transfers

- [x] Implement
- [x] Test (NumPy)
- [x] Test (JAX cross-validation)

**Paper:** `T^W(·)` for workers, `T^R(·)` for retirees — functions of individual state.

**Changes:**
- `LifecycleConfig`: Add `transfer_floor` (consumption floor, float, default 0.0). This is the standard Huggett-style consumption floor: `T(a, y) = max(0, c_floor - resources)`.
- Modify `_compute_budget()`: after computing disposable income, apply floor transfer.
- This is a simplified but widely-used formulation. Can be extended later to more complex means-testing.
- Files: `lifecycle_perfect_foresight.py`, `lifecycle_jax.py`

---

## Phase 4: Labor Supply

This is the largest single feature. It changes the utility function, the solve algorithm, and the simulation.

### Feature #1 — Endogenous labor hours (FOC approach)

- [x] Implement config parameters
- [x] Implement FOC-based solve (NumPy)
- [x] Implement FOC-based solve (JAX)
- [x] Implement simulation (record labor hours)
- [x] Implement OLG aggregation (aggregate labor supply)
- [x] Test (NumPy)
- [x] Test (JAX cross-validation)

**Paper:** `u(c, ℓ) = c^(1-σ)/(1-σ) - ν · ℓ^(1+φ)/(1+φ)`, labor hours `ℓ ≥ 0`.

**Changes:**
- `LifecycleConfig`: Add `labor_supply` (bool, default False), `nu` (labor disutility weight), `phi` (Frisch elasticity parameter = 1/φ).
- **Approach — FOC-based:** Given separable utility, the FOC for labor is `ν · ℓ^φ = λ · w · h · z · (1-τ_l-τ_p)`, where `λ = c^{-σ}`. For each candidate `(c, a')`, solve for optimal `ℓ` analytically: `ℓ* = max(0, (c^{-σ} · w·h·z·(1-τ_l-τ_p) / ν)^{1/φ})`. Only non-negativity constraint (no upper bound). This avoids adding a grid dimension.
- Modify `_solve_period()`: for each `(a, y, h)` state and each candidate `a'`, compute optimal `ℓ*` from FOC, then compute `c` from budget constraint with `ℓ*`, evaluate utility `u(c, ℓ*)`.
- Modify simulation to record labor hours.
- **State space impact:** No new state dimension if using FOC approach. Policy arrays gain a labor dimension in output: `l_policy(T, n_a, n_y, 1, n_y_last)` (with `n_h=1`).
- Files: `lifecycle_perfect_foresight.py`, `lifecycle_jax.py`, `olg_transition.py` (aggregate labor supply)

### Feature #6 — Wage income structure

- [x] Implement (part of Feature #1)

**Depends on:** Feature #1 (labor supply).

**Paper:** `y^L = w · h_j · f(s) · z · ℓ`.
**Current:** `wage = w · y_grid[i_y] · h_grid[i_h]`.

**Changes:**
- Once labor supply is added, wage income naturally becomes `w · y_grid[i_y] · h_grid[i_h] · ℓ`.
- This is essentially already handled by the labor supply implementation.
- Files: same as Feature #1

### Feature #7 — Endogenous retirement

- [x] Implement
- [x] Test (NumPy)
- [x] Test (JAX cross-validation)

**Paper:** Retirement is a choice within window `[J_R^min, J_R^max]`.

**Changes:**
- `LifecycleConfig`: Add `retirement_window` tuple `(min_age, max_age)`, default `None` (fixed retirement).
- During the retirement window, agents choose whether to retire. This is a discrete choice: `V(a, y, h) = max(V_work(a, y, h), V_retire(a, y_last, h))`.
- In backward induction, for ages in the retirement window, solve both the working and retired value functions and take the max.
- **State space impact:** No new state variable, but the solve is more complex in the retirement window.
- Files: `lifecycle_perfect_foresight.py`, `lifecycle_jax.py`

---

## Phase 5: Schooling & Children

### Feature #4 — Schooling phase and children

- [x] Implement
- [x] Test (NumPy)
- [x] Test (JAX cross-validation)

**Paper:** Children during first S working years, child consumption costs `c_y(j)`, education expenditures with subsidies `κ^school`.

**Changes:**
- `LifecycleConfig`: Add `schooling_years` (int, default 0), `child_cost_profile` (array of length T, default zeros), `education_subsidy_rate` (float, default 0.0).
- During schooling years (first S periods), budget constraint includes child costs that scale consumption: `(1 + τ_c)(1 + child_cost(j)) · c + a' = ...`.
- Education subsidies reduce the effective cost: net child cost = `(1 - education_subsidy_rate) * child_cost(j)`.
- This is a budget constraint modification — no new state variables.
- Files: `lifecycle_perfect_foresight.py`, `lifecycle_jax.py`

**Note:** Feature #3 (human capital) is absorbed into Phase 2 via age-dependent productivity transitions. The initial human capital level `h_0 = A_0 · e_s^γ` from education expenditure can be captured by education-type-specific initial productivity distributions (already supported via `edu_params`).

---

## Phase 6: Production & Public Sector

### Feature #8 — Public capital in production

- [x] Implement
- [x] Test

**Paper:** `Y = Z · (K^g)^{η_g} · K^α · L^{1-α}`.

**Changes:**
- `OLGTransition`: Add `K_g` (public capital stock), `eta_g` (public capital elasticity), `delta_g` (public capital depreciation).
- Modify production function: `Y = A * K_g**eta_g * K**alpha * L**(1-alpha)`.
- Modify firm FOCs for `r` and `w` to account for public capital.
- Files: `olg_transition.py`

### Feature #10 — Public investment

- [x] Implement
- [x] Test

**Depends on:** Feature #8.

**Paper:** `K^g_{t+1} = (1 - δ_g) · K^g_t + I^g_t`.

**Changes:**
- `OLGTransition`: Add `I_g_path` (public investment path) or `I_g_share` (share of GDP).
- Add public capital accumulation equation to the transition dynamics.
- Add `I_g` to government spending in the budget constraint.
- Files: `olg_transition.py`

### Feature #9 — Small open economy and sovereign debt

- [x] Implement
- [x] Test

**Paper:** SOE with `B_t` sovereign bonds, external rate `r*`.

**Changes:**
- `OLGTransition`: Add `economy_type` ('closed' | 'soe'), `r_star` (world interest rate), `B_path` (sovereign debt path).
- In SOE mode: `r = r*` (exogenous), no capital market clearing. Instead, current account adjusts.
- Government budget: `G + transfers + (1+r*)·B_t = revenue + B_{t+1}`.
- Resource constraint: `Y + r*·NFA = C + I + G + NX`.
- This is a major change to the equilibrium concept in `OLGTransition` but does NOT affect the lifecycle solve (agents just face given prices).
- Files: `olg_transition.py`

---

## Phase 7: Optional / Low Priority

### Feature #18 — Pension trust fund

- [x] Implement
- [x] Test

**Paper:** `S^pens_{t+1} = (1+r*)·S^pens_t + Rev^p_t - PENS^out_t`.

**Changes:**
- `OLGTransition`: Add `S_pens` (trust fund balance), accumulation equation.
- Mostly accounting — feeds into government budget constraint.
- Files: `olg_transition.py`

### Feature #19 — Defense and welfare-state production

- [x] Implement (simplified: defense spending as budget category)
- [x] Test

**Paper:** Defense spending, government labor, welfare capital `K^h`, production `H = F^W(K^h, N^h)`.

**Implementation:** Simplified version — `defense_spending_path` as exogenous spending in the government budget. The full government production function (K^h, N^h) can be extended later if needed.

**Changes:**
- `OLGTransition`: Add `defense_spending_path` (array, default None).
- Add defense spending to total government spending in budget constraint.
- Files: `olg_transition.py`

---

## Phase 8: Permanent Productivity Fixed Effect (σ_α)

**Status: Done (landed on `main` 2026-05-08, merge `4a9e4aa`).** First feature to add a new state variable to the lifecycle problem, breaking the original "no new state variables" constraint. Sub-phase commits: 8.1 `d96d525`, 8.2 `a556dd0`, 8.3 `704d75c`, 8.5a `b94779a`, 8.5b `ff8305e`, 8.6 `efe18e5`, 8.7 `9efbd4b`. (8.4 absorbed into 8.2/8.3 — pension scaling done in `_compute_budget`; bequests are α-agnostic.)

**Final calibration outcome** (Greek baseline, `n_alpha=5`, σ_α from LIS):

| | No FE | With σ_α |
|---|---|---|
| ν | 74.05 | 73.97 |
| β | 0.954 | 0.959 |
| `earnings_var_mean` | 0.112 | **0.169** |
| Wealth Gini | 0.85 | 0.85 |

The wealth-Gini residual (model 0.85 vs data 0.58) does not move with σ_α. Likely drivers are the discrete `z=0` unemployment state, the transfer floor mass point, the absence of a bequest motive, and limited initial wealth dispersion — diagnosed separately.

### Motivation

The LIS Greek pool estimation (`code/docs/INCOME_PROCESS_ESTIMATION_PLAN.md`, baseline ρ = 0.95) finds permanent within-education dispersion of `σ_α^(e) ∈ {0.367, 0.259, 0.318}` for low/medium/high. The current model has no fixed effect, so the AR(1) stationary variance `σ_η²/(1-ρ²) ∈ {0.030, 0.076, 0.058}` is the only source of within-education dispersion at age 25 — the model under-disperses initial earnings within low-education by a factor of ~4. Adding a permanent productivity shifter `α_i` aligns the model with the LIS variance profile and makes `σ_α^(e)` consumable rather than purely diagnostic.

Wage equation:
```
y^L = w_t · κ_j · z · exp(α),    α ~ N(0, σ_α^(e)²),    drawn at age 25, fixed for life
```

### Architectural decision: multiple-solve over state-expansion

Two approaches considered:

- **(A) Multiple solves** — solve `n_alpha` separate lifecycle problems per education, indexed by α-grid point. Cleaner code, isolated change. Solve cost ≈ `n_alpha` × baseline.
- **(B) State expansion** — add α as a 6th policy dimension `(T, n_a, n_y, n_h, n_y_last, n_alpha)`. Faster with JAX vectorization, more invasive (every solver/sim/cache touchpoint).

**Choice: (A)** for the first cut. (B) is a future optimization once validated.

### Discretization

α grid via Gauss–Hermite quadrature: `numpy.polynomial.hermite_e.hermegauss(n_alpha)` rescaled by `σ_α · √2`. **`n_alpha = 5`** as the default (matches HSV-style fixed-effect grids; smoother than 3-node and the `~5×` solve cost is acceptable for `n_alpha · solve_time ≈ 5 × 30s ≈ 2.5min` per cohort).

### Sub-phases

#### 8.1 Spec and data structures

- `LifecycleConfig`: add `n_alpha: int = 1` (default = no FE grid).
- `edu_params`: add `sigma_alpha: float = 0.0` (default = no FE).
- `_income_process()`: when `n_alpha > 1` and `sigma_alpha > 0`, build `self.alpha_grid` (length `n_alpha`) and `self.alpha_probs` from Gauss–Hermite. Expose as instance attributes.
- `calibrate.py:build_lifecycle_config()`: read `sigma_alpha` and `n_alpha` from JSON and pass to `LifecycleConfig`.
- `calibration_input_GR.json`: add `sigma_alpha` per education (initially `0.0` to preserve the current baseline).
- Files: `lifecycle_perfect_foresight.py`, `calibrate.py`, `calibration_input_GR.json`

**Acceptance:** all existing tests pass; `sigma_alpha=0` and `n_alpha=1` recover prior behavior exactly.

#### 8.2 Lifecycle solve (NumPy reference)

- `solve_lifecycle()`: when `n_alpha > 1`, loop over α-grid. For each `α_idx ∈ {0, …, n_alpha-1}`:
  - In `_compute_budget()`, multiply effective wage income by `exp(alpha_grid[α_idx])`.
  - Run the existing backward-induction solve.
  - Store policies under a new leading axis: `a_policy_alpha[α_idx, t, ...]`, plus c, l, value counterparts.
- When `n_alpha == 1`, behavior identical to current (single solve, no new dimension).
- Files: `lifecycle_perfect_foresight.py`

**Acceptance:** with `n_alpha=1`, all existing OLG transition tests pass without changes.

#### 8.3 Simulation init and forward (NumPy)

- `_simulate_sequential()`:
  - At `t=0`, sample `alpha_idx_sim` for each agent via `np.random.choice(n_alpha, size=n_sim, p=alpha_probs)`.
  - For each agent `i`, use `a_policy_alpha[alpha_idx_sim[i]]` (and c, l, value counterparts) for their full path.
  - Compute realized earnings using `exp(alpha_grid[alpha_idx_sim[i]])` multiplier in the wage formula.
- Add `alpha_idx_sim` (or equivalent realized `alpha_sim`) as a new entry to the simulation output tuple. Update `OLGTransition.simulate_transition` consumers and `fiscal_experiments.py` to thread it through unchanged (diagnostic only).
- Files: `lifecycle_perfect_foresight.py`, `olg_transition.py`, `fiscal_experiments.py`

**Acceptance:** simulated `Var(log y)` at age 25 within an education stratum ≈ `σ_α^(e)²`; at age 60 ≈ `σ_α^(e)² + σ_η^(e)²/(1-ρ²)`.

#### 8.4 Pension and bequest accounting

- Pension formula `PENS = max(ρ · w · κ_{J_R} · [λ z_last + (1-λ) z̄], b_min)` uses `z_last`. Update to multiply the wage term by `exp(α_i)` so high-α retirees receive proportionally higher pensions.
- Bequest redistribution stays lump-sum and unaffected by α (no change needed).
- Files: `lifecycle_perfect_foresight.py`

#### 8.5 JAX backend mirror

- Mirror 8.2–8.3 in `lifecycle_jax.py`: `jax.lax.scan` (or `vmap`) over the α-grid for solve; `vmap` over agents in simulation. The Metal/CPU caveat (set `JAX_PLATFORM_NAME=cpu`) already documented.
- Re-evict `_jax_policy_batch` after MIT shock stitching as today.
- Files: `lifecycle_jax.py`

**Acceptance:** JAX cross-validation tests (NumPy ↔ JAX agreement to 1e-6) pass with `sigma_alpha > 0`.

#### 8.6 Tests

- **Backward compat:** `sigma_alpha=0` → existing 21-tuple outputs identical (regression).
- **α permanence:** `alpha_idx_sim[0,i] == alpha_idx_sim[T-1,i]` for all `i`.
- **Wage decomposition:** `y_sim[t,i] / (w_t · κ_t · z_sim[t,i]) ≈ exp(alpha_grid[alpha_idx_sim[i]])` (within numerical tolerance, employment subsample).
- **Variance profile (ages 25 & 60):** within-education `Var(log y)` matches `σ_α²` and `σ_α² + σ_η²/(1-ρ²)` to within 5% with `n_sim=10000`.
- **MIT shock A[0] predetermination:** still exactly 0.0 across both backends with `sigma_alpha > 0`.
- Files: `test_olg_transition.py` (new test class `TestFixedEffect`)

#### 8.7 Re-calibrate Greek baseline

- Set `sigma_alpha` per education in `calibration_input_GR.json` to the LIS estimates `{0.367, 0.259, 0.318}` (low/med/high) and `n_alpha = 5`.
- Re-run `python calibrate.py --config calibration_input_GR.json --backend jax`.
- Compare validation moments before/after: wealth Gini, income Gini, p90/p10, mean Var(u), slope Var(u). Expectations:
  - Within-edu var(log y) at age 25 should now match LIS data (currently severely under-dispersed).
  - Wealth Gini likely *worsens* (currently 0.85 vs data 0.58, already an overshoot). The wealth-Gini residual is therefore not driven by earnings dispersion and a separate diagnosis is needed (transfer floor, unemployment dynamics, bequests).

### Risks

- **MIT shock stitching with α grid:** the pre-transition baseline policy must be solved per-α, and the stitching must preserve the per-α policy correctly. May need `_mit_baseline_cache` keyed by `(edu_type, birth_period, α_idx)`.
- **`OLGTransition` cohort caching:** `_cohort_panel_cache` and `_period_cache` are sized for the current state space. Adding the α dimension requires verifying the keys still discriminate correctly.
- **Computational cost:** `n_alpha=5` means ~5× the solve and simulate cost. Calibration goes from ~3 min to ~15 min per evaluation; SMM (60 evaluations) from 3 hours to ~15 hours. May need to drop `n_alpha=3` if wall-clock becomes prohibitive.
- **α–z independence assumption:** standard but possibly violated in data (high-α workers may have different shock variance). If violated, σ_η will be biased. Out of scope here.

### Computational cost

`n_alpha = 5` → ~5× baseline. With current ~30s per cohort solve, ~2.5min per evaluation. Full SMM optimization ~15 min if `~60` evaluations.

---

## Phase 9: Wealth-Distribution Margins (warm-glow bequest + initial wealth)

**Status: Planned (added 2026-05-11).** Two sub-features both targeting the wealth-distribution residual that Phase 8 left untouched: model wealth Gini 0.85 vs Greek HFCS 0.58, zero-wealth fraction 0.43 vs 0.011.

### Motivation

After Phase 8, the income process is correctly disciplined by LIS data: within-education `Var(log y)` matches the LIS-MD target. The remaining wealth-distribution gap is therefore *not* about earnings — it is about saving-side and initial-condition margins:

1. **No bequest motive.** Agents currently treat death as the end of utility and consume the last unit of wealth. Without a "joy of giving" or precautionary-bequest term, the model has no force generating a long upper tail of the wealth distribution. De Nardi (RES 2004) and Cagetti & De Nardi (JPE 2008) show this is the single largest driver of top wealth shares in heterogeneous-agent models.
2. **Initial wealth degenerate at 0.** The Greek JSON sets neither `initial_assets` nor `initial_asset_distribution`, so every age-25 agent starts with wealth = 0. In Greek HFCS, age-25 households have a *distribution* — many at zero, but a sizeable fraction with inherited or parental-transfer wealth. The mass at zero in the model is partly an artifact of the degenerate initial condition.

### Sub-features

#### 9A. Warm-glow bequest motive (De Nardi-style)

Add a utility term at death:
$$ u_b(b) = \varphi \cdot \frac{(b + \bar b)^{1-\sigma}}{1-\sigma} $$

where `b = a_j` (assets at death) and `(\varphi, \bar b)` are two new parameters:

- **`varphi`** (`bequest_weight`) — overall weight on bequest utility. Larger → more savings at the top.
- **`bbar`** (`bequest_shifter`) — luxury parameter. With `bbar > 0`, bequest is a luxury good: poor agents don't bequest, rich agents do. This is what generates the upper tail.

Mortality is already in the code (`survival_probs`, `bequest_sim`). Adding the preference requires modifying the period value function:

V_j(s) = max_a' { u(c, l) + β · [π · E V_{j+1}(s') + (1-π) · u_b(a')] }

i.e., the value of dying with assets `a'` is `u_b(a')`, weighted by death probability `(1-π)`.

#### 9B. Initial wealth distribution

Set `LifecycleConfig.initial_asset_distribution` to an empirical distribution of net household wealth at age 25 from Greek HFCS. The infrastructure for this already exists — it's just a `(n_samples,)` array in the JSON config; agents sample from it at simulation start. No code changes needed.

### Calibration

Adding **two** internal parameters (`varphi`, `bbar`) requires **two** new targeted moments. Candidates from HFCS Greece:

- **Top-decile wealth share** (top 10%) — identifies `bbar` strongly (luxury-bequest shifter sharpens the upper tail).
- **Wealth Gini** — identifies `varphi` (overall savings strength).
- **Top-quintile wealth share** (top 20%) — alternative if top-decile is noisy.
- **`p90/p10` wealth ratio** — robust dispersion.

Likely SMM problem after Phase 9: free parameters (β, ν, φ, b̄) against targets (A/Y, h̄, top10%_wealth, wealth_Gini). 4-by-4 system.

### Sub-phases

#### 9.1 Initial wealth distribution (easy first step)

- Obtain Greek HFCS data (see data sources below).
- Build per-education or pooled initial-wealth empirical distribution for households age 25–29.
- Write into `calibration_input_GR.json` under `"initial_asset_distribution": [...]` (or per-education `edu_params[e]['initial_asset_distribution']`).
- No code changes — `lifecycle_perfect_foresight.py` already samples from this array at t=0.
- Acceptance: re-run calibration; check `zero_wealth_fraction` falls toward the data value (0.011).

#### 9.2 Warm-glow bequest in NumPy backend

- Add `bequest_weight`, `bequest_shifter` to `LifecycleConfig` (defaults 0.0 — feature OFF).
- Modify `_solve_state_choice()` / `_solve_period()` to include `(1-π) · u_b(a')` in the value at non-terminal periods with mortality.
- Terminal period: V_T includes only `u_b(a')` since `π = 0` at death-certain age.
- Files: `lifecycle_perfect_foresight.py`.
- Acceptance: with `bequest_weight = 0`, all prior behavior unchanged (regression).

#### 9.3 Warm-glow bequest in JAX backend

- Mirror 9.2 in `lifecycle_jax.py` (`compute_budget_jax` / `solve_period_jax` / `_solve_terminal_period_jax`).
- JAX cross-validation: V agrees with NumPy to 1e-6 with bequest motive on.

#### 9.4 Re-calibrate Greek baseline

- Add HFCS top-decile-wealth-share and wealth-Gini to `calibration.targets`.
- Run SMM with 4 free parameters (β, ν, φ, b̄).
- Validate: wealth Gini, top-decile share, zero-wealth fraction, all closer to data.

### Data sources to obtain

For both sub-features below, the canonical source is **Eurosystem Household Finance and Consumption Survey (HFCS)**, the Greek microdata managed by the Bank of Greece on behalf of the ECB.

| Need | Source | Specifics |
|---|---|---|
| Top decile / top quintile **wealth share** | HFCS Statistical Tables, Eurosystem | Greek wave (latest available: 2021/HFCS Wave 4). Look for "Distribution of net wealth by percentile" — typically tables show shares for top 1%, top 5%, top 10%, top 20%, bottom 50%. |
| Wealth **Gini** (cross-check) | HFCS Statistical Tables, Eurosystem | Same source. Greek wealth Gini was 0.58 in HFCS Wave 3 (2017). |
| **Net wealth percentiles** (P10, P25, P50, P75, P90, P95, P99) | HFCS Statistical Tables, Eurosystem | Used as targets if top-decile share is too noisy. |
| **Age-25 to 29 wealth distribution** (initial wealth) | HFCS microdata, Greek subset | Need either the empirical distribution itself (n_samples values of net wealth) or quantile statistics (P0, P10, P25, P50, P75, P90) within the 25–29 age band. The Bank of Greece publishes summary stats by age; microdata requires application. |
| Median wealth by age band (validation) | HFCS Statistical Tables / OECD WDD | Reference points by 10-year age bracket. |

**Access notes for HFCS microdata:**

- **Aggregate tables**: free on the ECB HFCS portal (`ecb.europa.eu/pub/economic-research/research-networks/html/researcher_hfcn.en.html`), no application needed.
- **Microdata**: requires application to the Bank of Greece HFCS contact point, via the ECB HFCN data-access portal. Typically a research-purpose declaration plus institutional affiliation. Processing time: 2–8 weeks.
- **Alternative if microdata is slow**: use HFCS published cross-tabs by age band as quantile statistics, then construct an empirical distribution via inverse-CDF sampling between the published percentiles. Coarser but immediately available.

The **top-decile and Gini targets are immediately obtainable** from the public HFCS Statistical Tables — no application needed. **Initial-wealth distribution by age band** is the only piece that may require microdata or a fallback to the published quantile reconstruction.

### Computational cost

Bequest motive: adds one term to the period value function (constant cost per state evaluation). With Phase 8's `n_alpha = 5`, no further multiplication. Total SMM optimization with 4 free parameters: probably 100–200 NM iterations × 2.5 min/eval ≈ 5–8 hours wall time (versus ~17 min for Phase 8.7).

Initial-wealth distribution: zero solve-side cost. Simulation-side, just a different `t=0` draw.

### Risks

- **Warm-glow vs accidental bequest**: the current code already has *accidental* bequests (assets at death redistributed as `bequest_lumpsum`). Adding warm-glow changes household preferences but not the aggregate accounting — bequests are still received as a lump-sum transfer. No accounting fix needed, just utility-side modification.
- **Calibration identifies `bbar` and `varphi` separately**: in principle both shift the wealth distribution. The luxury shifter `bbar` has its biggest effect on the *shape* (long upper tail), while `varphi` shifts the overall *level* of saving. Joint identification should work with two distinct distributional moments, but worth verifying via local sensitivity.
- **Numerical**: the bequest term enters as `(a + bbar)^(1-σ)`. With σ = 2.0, this is convex and bounded below by `bbar^(1-σ)`. No solver problems anticipated.

---

## Phase 10: Test-Suite Audit

**Status: Planned (added 2026-05-18).** Independent audit of `test_olg_transition.py` + `test_fiscal_experiments.py` + `test_income_process.py` to repair signal loss in the test suite. Triggered by the 2026-05-18 `mu_y` debugging session, which surfaced three suite-quality issues at once: (a) the bug was uncaught by 132 tests; (b) `TestPhase6Features::test_public_capital_increases_output` hangs indefinitely on macOS ARM; (c) `test_constant_r_small_economy` was passing for the wrong reason (relied on an inflated y-level from the bug).

### Motivation

Today the suite returns either green or several pages of noise; in both cases it provides limited actionable information. Existing skip-strings (15 JAX/Metal tests, 1 pre-existing `TestLaborSupply::test_l_sim_in_output` failure, 1 hang) are accumulated in shell flags rather than `pytest.skip` decorators, so each new contributor has to rediscover them. The `mu_y` bug went undetected for the entire Phase 8 cycle despite extensive cross-validation tests because no test asserted accounting identities at the aggregator level.

### Audit deliverables

Run as an **independent read-only Agent** (no edits without explicit approval). Output is a written report, triaged. The audit has four asks, in order:

1. **Triage every currently failing or skipped test.** Each one lands in exactly one bucket:
   - (a) genuine bug — ticket and link to a planned fix
   - (b) environment-specific (macOS/Metal/JAX) — convert to `@pytest.mark.skipif` with the platform reason in the message, drop from `-k` exclusion strings
   - (c) brittle/wrong assertion — fix the assertion (e.g., test that `K > 0` should be `K > some_minimum_threshold` tied to model parameters, not `0`)
   - (d) obsolete (no longer testing what was intended after refactors) — delete

2. **Runtime profile.** `pytest --durations=20`. Identify the 5–10 slowest tests; explain why each is slow (large `n_sim`, full transition simulation when a steady-state check suffices, etc.); propose tightenings. The `test_public_capital_increases_output` hang should get a root-cause diagnosis (likely a degenerate path interacting with Phase 6 public-capital code and `get_test_config`'s `n_y=2` setup) — fix or skip with a documented reason.

3. **Brittle-assertion sweep.** Grep for assertions of the form:
   - `assert np.all(X > 0)` on simulation aggregates — fragile to calibration drift
   - `rtol=1e-5` or tighter against simulated output (not against analytical references) — fragile to seed and discretization choices
   - `assert abs(... - hardcoded) < tol` where `hardcoded` is a magic number not derived from the test's setup
   - Tests that depend on `LifecycleConfig` defaults rather than building an explicit config
   
   Replace with structural assertions where possible. Examples: labor share = 1−α (Cobb-Douglas identity), aggregate budget identity `C + I + G = Y` in closed-economy mode, `tax_revenue ≥ 0`, `pensions/Y ≤ pension_replacement_default × employed_share`.

4. **Coverage gaps.** What should have caught the `mu_y` bug? The post-hoc answer is "accounting-identity assertions at the calibration step":
   - `C/Y ≤ 1 + |NFA|/Y` (consistent with resource constraint)
   - `primary_balance/Y ∈ [−0.10, +0.10]` (baseline is a fiscal SS, not 140% deficit)
   - `pensions/Y ≤ 0.20` (any plausible OECD calibration)
   - `tax_revenue/Y ∈ [0.20, 0.55]` (OECD bounds)
   
   These would have flagged the bug at the calibration step instead of fiscal-experiment time. Catalog the rest of these structural invariants and propose a `test_accounting_identities.py` companion to `test_income_process.py`.

### Output format

A single markdown report at `code/docs/TEST_SUITE_AUDIT.md` with:

- **Inventory table.** One row per test in (file × class × method) order. Columns: status (pass/fail/skip/hang), runtime (s), bucket (a–d from triage), proposed action.
- **Hang report.** Section on `test_public_capital_increases_output` with reproducer, suspected cause, recommended fix.
- **Brittle-assertion list.** File:line citations + suggested replacement.
- **Coverage-gap proposal.** List of accounting identities to assert, with implementation sketch.

After review, sub-tasks 1–4 can be executed in any order as separate phases.

### Risks

- The audit Agent may propose deleting tests that are slow but provide genuine coverage. Decision authority stays with the user; the audit is read-only.
- Fixing brittle assertions may cause new failures if previously-passing tests were silently broken (passing for the wrong reason, as `test_constant_r_small_economy` was). This is a feature, not a bug — surface them.

### Computational cost

Read-only audit pass: ~30 min wall clock (one full `pytest --durations` run + grep + report writing). Subsequent fixes: scoped per-bucket, each typically a few-minute change.

---

## Implementation Order Summary

| Phase | Features | Key Changes | Risk |
|-------|----------|-------------|------|
| 1 | #11, #17, #20 | Pension floor, govt spending, age-dependent medical | Low |
| 2 | #3+#5, #2, #16 | Age-dependent productivity (unified), survival risk, bequest tax | Medium |
| 3 | #14, #15 | Progressive taxation, means-tested transfers | Low-Medium |
| 4 | #1, #6, #7 | Labor supply (FOC-based), wage structure, endo retirement | High |
| 5 | #4 | Schooling phase and children | Low-Medium |
| 6 | #8, #10, #9 | Public capital, public investment, SOE/sovereign debt | Medium-High |
| 7 | #18, #19 | Pension trust fund, govt production | Low priority |
| 8 | σ_α | Permanent productivity fixed effect (`n_alpha=5`); first feature to add a state variable | Medium-High |
| 9 | warm-glow bequest + initial wealth | De Nardi-style bequest utility (`varphi`, `bbar`) + empirical initial-wealth distribution from HFCS Greece; addresses the wealth-distribution residual (model Gini 0.85 vs data 0.58) | Medium |
| 10 | test-suite audit | Independent read-only audit of the pytest suite; triage failures, profile runtime, sweep brittle assertions, propose accounting-identity coverage | Low (read-only) |

---

## Testing Strategy

Each phase follows the same testing protocol:

1. **Backward compatibility:** All new features default to OFF (e.g., `pension_min_floor=0.0`, `survival_probs=None`, `labor_supply=False`). Existing tests must pass unchanged after each phase.

2. **Feature unit tests:** Each feature gets dedicated tests in `test_olg_transition.py`:
   - Verify the feature activates correctly when enabled
   - Check boundary cases (e.g., pension floor = 0 should match no-floor, survival_probs = 1.0 should match deterministic)
   - Validate against analytical solutions where available (e.g., FOC-based labor supply has closed-form)

3. **JAX cross-validation:** After each phase that touches the lifecycle solve or simulation:
   - Value function agreement: `|V_jax - V_numpy| < 1e-6` for all states
   - Policy agreement: identical optimal indices
   - Simulation distributional match: mean profiles within 3 standard errors (n_sim >= 5000)

4. **Regression testing:** Run the full OLG transition (`python olg_transition.py --test`) before and after each phase. Compare:
   - Aggregate K, L, Y levels
   - Government budget balance
   - Consumption and wealth profiles by age

5. **Feature-specific validation:** Compare model moments against known benchmarks:
   - Phase 2: Mortality-adjusted wealth profiles
   - Phase 3: Tax revenue under progressive schedule, transfer spending
   - Phase 4: Labor supply elasticity, hours profile by age
   - Phase 6: K/Y ratio with public capital, SOE current account

## JAX Backend Strategy

- **Phase 1-3:** Straightforward — same state space, just different computations. Update both backends in lockstep.
- **Phase 2 (unified productivity):** `P_y` shape changes from `(n_y, n_y)` to `(T, 1, n_y, n_y)` (health dimension trivial with `n_h=1`). P_y slices passed per-period in the `lax.scan` loop.
- **Phase 4 (labor supply):** FOC-based approach avoids new grid dimension, keeping JAX compatibility simple. The FOC computation is element-wise and fully vectorizable.
- **Phase 5 (schooling):** Budget constraint change only — no state space impact.
- **Phase 6:** Changes are in `olg_transition.py` (NumPy/Numba), not in the lifecycle backends.

## Key Files

| File | Role | Phases Affected |
|------|------|----------------|
| `lifecycle_perfect_foresight.py` | NumPy lifecycle solve + simulate | 1, 2, 3, 4, 5 |
| `lifecycle_jax.py` | JAX lifecycle solve + simulate | 1, 2, 3, 4, 5 |
| `olg_transition.py` | OLG aggregation, GE, govt budget | 1, 2, 3, 4, 5, 6, 7 |
| `test_olg_transition.py` | Test suite | All phases |

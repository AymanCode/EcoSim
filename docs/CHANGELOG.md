# EcoSim Development Changelog

This document tracks all implementation changes, improvements, and features added to the EcoSim project.

---

## [2026-03-12] Engineering Hardening Pass — Config Centralization, Determinism Fixes, Wage Telemetry Pipeline

### Overview

Full engineering audit of the simulation core, focused on eliminating hardcoded constants, fixing non-deterministic behavior, correcting broken economic formulas, and wiring up real-time wage telemetry to the frontend dashboard. This pass was motivated by the observation that many CONFIG parameters existed in `config.py` but were never actually referenced in the simulation code — the agent logic used divergent hardcoded values instead.

### Design Philosophy

Every fix in this pass follows a principle: **the simulation's behavior should be fully controllable from `config.py`, reproducible across runs, and observable in real-time from the dashboard.** Hardcoded constants make it impossible to tune the simulation without code changes. Non-deterministic behavior makes debugging impossible. And if the frontend can't show what's happening inside agents, you can't validate that your economic model is doing what you think it is.

---

### 1. Configuration Centralization — Why Dataclass Config Over Hardcoded Constants

**Problem**: The codebase had a well-designed `CONFIG` singleton with nested dataclasses (`HouseholdConfig`, `FirmConfig`, `MarketMechanicsConfig`, etc.), but the actual simulation code in `agents.py` and `economy.py` used hardcoded magic numbers instead. For example, `config.py` defined `base_wage_decay: float = 0.97` but `agents.py` used a hardcoded `0.92`. This meant changing config values had zero effect on simulation behavior — a silent, dangerous divergence.

**Why dataclass-based config?** We chose Python `@dataclass` with frozen-style defaults over alternatives like:
- **YAML/JSON files**: Would add file I/O overhead on every tick and require parsing. Dataclasses give us type safety, IDE autocomplete, and `__post_init__` validation for free.
- **Environment variables**: Too flat for nested config (household vs firm vs market settings). No type safety.
- **Global dicts**: No autocompletion, no validation, easy to typo keys silently.

The dataclass approach lets us add `__post_init__` validators (e.g., `min_savings_rate <= max_savings_rate`, range tuple lo<=hi checks) that catch misconfiguration at startup, not 500 ticks into a simulation run.

**What was wired up**:

| Area | Old (Hardcoded) | New (CONFIG Reference) |
|------|----------------|----------------------|
| Wage decay base | `0.92` | `CONFIG.households.base_wage_decay` (0.97) |
| Duration pressure cap | `0.45` | `CONFIG.households.duration_pressure_cap` (0.35) |
| Min decay factor | `0.4` | `CONFIG.households.min_decay_factor` (0.5) |
| Wage floor | `$5.0` | `CONFIG.households.wage_floor` ($10.0) |
| Desperation scaling | hardcoded `20.0` ticks, `0.9` | `CONFIG.households.desperation_*` fields |
| Bankruptcy threshold | `-1000.0` | `CONFIG.market.bankruptcy_threshold` |
| Zero-cash max streak | `12` | `CONFIG.market.zero_cash_max_streak` |
| Price ceiling / tax rate | `50.0` / `0.25` | `CONFIG.market.price_ceiling` / `price_ceiling_tax_rate` |
| Wage overpaying guard | hardcoded fractions | `CONFIG.firms.max_labor_share`, `minimum_wage_floor`, `max_wage_decrease_per_tick` |
| Rent affordability | hardcoded `0.30` | `CONFIG.labor_market.rent_affordability_share` |
| Rent adjustment thresholds | magic numbers | `CONFIG.labor_market.occupancy_*_threshold`, `rent_increase_*`, `rent_decrease_*` |

**New config fields added**: `zero_cash_max_streak`, `rent_affordability_share`, `rent_floor`, occupancy thresholds (high/good/moderate/low), rent adjustment multipliers, `rent_shortage_multiplier`, `rent_shortage_interval_ticks`.

---

### 2. Determinism Fixes — Why Seeded RNG Over `np.random`

**Problem**: `agents.py` used `np.random.uniform(-0.25, 0.25)` (global RNG state) in the wage decay path. This means two simulation runs with identical config produce different results. When you're debugging why unemployment spiked at tick 347, non-determinism makes reproduction impossible.

**Why per-agent seeded RNG?** We replaced global `np.random` calls with `np.random.default_rng(seed=self.household_id ^ hash(category))`. This gives each agent a deterministic random stream derived from its ID, so:
- Same agent, same tick → same random value across runs
- Different agents → different streams (no correlation)
- No global state pollution between agents

We chose `default_rng` over `RandomState` because NumPy's documentation recommends it as the modern API with better statistical properties (PCG64 vs Mersenne Twister).

**Docstring updated**: Changed "All behavior is deterministic" → "deterministic when seeded" to accurately reflect the contract.

---

### 3. Economic Formula Corrections — Why These Bugs Mattered

#### Property Tax: Taxing Value, Not Cash

**Problem**: Property tax was calculated on `firm["cash_balance"]` instead of assessed property value. This meant a housing firm with $1M cash but 2 rental units paid more tax than a firm with $100 cash but 200 units. This is economically backwards — property tax should reflect the value of the property, not the firm's liquidity.

**Fix**: `rental_units * rent_per_unit * 52.0` (annualized rental income as property value proxy). We chose annualized rent over alternatives like purchase price (which doesn't exist in this model) or replacement cost (which would require a construction cost model we don't have).

#### Housing Firm Workforce Churn

**Problem**: Housing firms fired ALL employees every tick and rehired from scratch. This created artificial unemployment spikes and wasted the skill growth that employees had accumulated. In a real economy, firms retain a skeleton crew even during downturns.

**Fix**: Retain `min_staff = max(min_skeleton_workers, min_target_workers)` instead of laying off everyone. We chose a max-of-two-floors approach because either constraint alone can be too permissive — you need both a hard minimum (skeleton crew) and a demand-based minimum (target workers).

#### Unemployed Housing Affordability

**Problem**: Unemployed households used `income = 0.0` for housing affordability checks, which meant they could never qualify for any housing even when receiving unemployment benefits. This created a permanent homelessness trap.

**Fix**: Use `self.government.unemployment_benefit` as the income floor. The government already pays this benefit — the affordability check just wasn't accounting for it.

#### Division-by-Zero in Wage Overpaying Guard

**Problem**: `adjust_wages_if_overpaying` divided by `revenue` without guarding against zero. A firm with zero revenue (e.g., just started, no sales yet) would crash the simulation.

**Fix**: `max(revenue, 1e-9)`. We chose `1e-9` over `0.01` or `1.0` because it's small enough to never affect real calculations but large enough to avoid floating-point denormals.

#### Pre-Validation in `apply_purchases`

**Problem**: `apply_purchases` mutated `cash_balance` before validating the purchase could succeed, potentially leaving agents in inconsistent states if downstream logic failed.

**Fix**: Added pre-validation check before mutation. This follows the "validate then mutate" pattern — never modify state until you know the operation will succeed.

---

### 4. Wage Telemetry Pipeline — Why the Frontend Showed All Zeros

**Problem**: The frontend's "Wage Expectations" and "Target Wage Drivers" panels displayed `$0.00` for all values. Two root causes:

#### Root Cause 1: Wage Percentiles Computed From Empty Data

`economy.py` computed market wage percentiles (`cached_wage_percentiles`) from `firm_labor_outcomes["actual_wages"]`, which only contains wages for **newly hired** employees in that tick. In a stable economy with no turnover, this list is always empty, so percentiles stayed `(None, None, None)` permanently.

**Why this design was wrong**: The percentiles are used as `marketAnchorEstimate` — a reference point for what the labor market pays. Using only new-hire wages is like measuring average salary from only job postings, ignoring everyone currently employed. It gives a biased (or empty) picture.

**Fix**: Changed to iterate `firm.actual_wages` for ALL currently employed workers across all firms. This is O(total_employees) per recompute (every 5 ticks), which is acceptable since we already iterate all households and firms every tick.

#### Root Cause 2: No Fallback for Uninitialized Percentiles

The server read `cached_wage_percentiles` with `(None, None, None)` as the default. When percentiles were `None`, the frontend received `null`, and `null || 0` in JavaScript rendered as `$0.00`.

**Fix**: Added fallback to `mean_wage` from `compute_household_stats()` when percentiles aren't yet computed. We chose `mean_wage` over `median_wage` or a hardcoded default because the mean is always available (computed from all employed workers) and gives a reasonable approximation until percentiles are computed.

#### Data Flow Architecture

The wage telemetry pipeline follows a three-layer architecture:

```
Agent Layer (agents.py)
  └─ HouseholdAgent.apply_labor_outcome() updates expected_wage, reservation_wage each tick
  └─ Wage decay uses CONFIG.households.* for duration/cash/health pressure factors

Stats Layer (run_large_simulation.py)
  └─ compute_household_stats() vectorizes all h.expected_wage into numpy array
  └─ Returns mean_expected_wage, mean_unemployed_expected_wage

Server Layer (server.py)
  └─ Builds per-subject expectedWageReason dict with:
     mode (EMPLOYED_ANCHOR | UNEMPLOYED_DECAY | TRAINING_TRACK)
     durationPressure, cashPressure, healthPressure, decayFactor
     marketAnchorEstimate (from economy.cached_wage_percentiles)
     tags (descriptive labels for active pressure sources)
  └─ Sends via WebSocket as part of trackedSubjects payload
```

**Why compute pressures server-side instead of agent-side?** The pressure values are diagnostic — they explain *why* expected_wage changed, but they don't affect agent behavior. Computing them in the server keeps the agent's hot path clean and avoids storing diagnostic fields on 10K+ agent objects every tick.

---

### 5. Healthcare Test Modernization — Why Tests Broke and How We Fixed Them

**Problem**: 7 contract tests failed because they set up healthcare demand using the **old annual-plan model** (`care_plan_due_ticks`, `care_plan_heal_deltas`) but the simulation code had been refactored to use the **new episode-based model** (`pending_healthcare_visits`, `next_healthcare_request_tick`, `should_request_healthcare_service()`).

**Why the old model was replaced** (context from prior work): The annual-plan model generated a fixed schedule of visits at the start of each 52-tick window. This created unrealistic demand patterns — all visits were pre-determined regardless of how the patient's health changed. The new episode-based model is probabilistic and adaptive: sicker patients trigger episodes more often, episode size scales with missing health, and follow-up spacing adjusts based on current health.

**What changed in tests**:
- Replaced `care_plan_due_ticks = [0]` / `care_plan_heal_deltas = [0.2]` with `pending_healthcare_visits = N` / `next_healthcare_request_tick = 0`
- Removed assertions on `care_plan_due_ticks` length (no longer used)
- Updated health restoration assertions to be range-based (`health > 0.3`) instead of exact (`health == 0.5`) since heal deltas are now computed dynamically from missing health
- For integration test: explicitly set `pending_healthcare_visits` for low-health subjects and suppressed requests for healthy subjects via future `next_healthcare_request_tick`

**Files updated**: `test_contracts_healthcare.py`, `test_contracts_behavior.py`, `test_contracts_integration.py`

---

### 6. Server Security Hardening

**Problem**: `server.py` had `allow_origins=["*"]` (accepts requests from any domain), no input validation on WebSocket messages, and no structured logging.

**Changes**:
- **CORS**: Replaced `["*"]` with env-configurable `CORS_ORIGINS`. Set `allow_credentials=False`, restricted methods to `["GET", "POST", "OPTIONS"]`. Why env-configurable? Because `localhost:3000` is valid in dev but not in production — the deployment environment should control this, not the code.
- **WebSocket validation**: Added payload size limit (1MB), JSON parse validation, command whitelist. Without these, a malformed or oversized message could crash the server or cause memory exhaustion.
- **Pydantic validation**: Added `SetupConfig` model with bounds (num_households 3-100K, num_firms 1-1K). Why Pydantic over manual validation? It gives us type coercion, error messages, and OpenAPI schema generation for free.
- **Structured logging**: Added `RotatingFileHandler` (10MB, 5 backups). Why rotating? Simulation logs can grow unbounded — 10MB × 5 backups = 50MB max disk usage.
- **Health endpoint**: Added `/health` for container orchestration readiness probes.

---

### 7. CI/CD Pipeline and Tooling

**Problem**: No automated testing, no code formatting enforcement, no type checking.

**Added**:
- **GitHub Actions CI** (`.github/workflows/ci.yml`): Matrix testing across Python 3.10-3.12, pip caching, pytest with coverage, lint job (black, isort, flake8). Why matrix testing? Python version differences (e.g., `match` statement in 3.10+, type hint changes) can cause silent breakage.
- **`pyproject.toml`**: Centralized tool config. Why `pyproject.toml` over separate config files? PEP 621 standardizes this — one file for black, isort, mypy, pytest config instead of 4 separate dotfiles.
- **`requirements-dev.txt`**: Separated dev dependencies (pytest, black, mypy) from runtime (`requirements.txt`). Why separate? Production containers shouldn't install test frameworks.
- **`.gitattributes`**: LF line endings for source files. Why? Mixed line endings cause phantom git diffs on cross-platform teams and break `git diff` patch application.
- **`pytest.ini`**: Updated `testpaths`, added `--tb=short` for cleaner CI output.

---

### Files Updated

- `backend/agents.py` — Config wiring, determinism fix, economic formula corrections
- `backend/economy.py` — Bankruptcy config, rent config, property tax fix, wage percentile fix
- `backend/config.py` — New fields, `__post_init__` validators
- `backend/server.py` — CORS, input validation, logging, Pydantic, wage telemetry, health endpoint, wage percentile fallback
- `backend/run_large_simulation.py` — `compute_household_stats` already correct (no changes needed)
- `backend/tests_contracts/test_contracts_healthcare.py` — Migrated to episode-based healthcare model
- `backend/tests_contracts/test_contracts_behavior.py` — Same migration
- `backend/tests_contracts/test_contracts_integration.py` — Same migration
- `requirements.txt` — Pinned versions
- `requirements-dev.txt` — New (dev dependencies)
- `pyproject.toml` — New (tool configuration)
- `.github/workflows/ci.yml` — New (CI pipeline)
- `.gitattributes` — New (line ending normalization)
- `pytest.ini` — Updated test paths

### Validation

- All 26 contract tests pass: `pytest backend/tests_contracts -q` → `26 passed`
- Wage percentiles now populate correctly: `(27.94, 29.05, 30.18)` after 10 ticks (was `(None, None, None)`)
- `avgExpectedWage` returns ~$34.60 (was `$0.00`)
- `marketAnchorEstimate` returns real percentile values (was `$0.00`)

---

## [2026-03-06] EcoSim 2.0 - Performance Optimization & Health/Food System Overhaul

### Overview

Major performance optimization pass (33-38% speedup) via precomputed lookups and eliminated redundant loops, plus a full rewrite of the food consumption and health systems to use realistic proportional mechanics instead of broken binary thresholds.

### Performance Optimizations

- **Eliminated `_choose_firm_based_on_style`** (was 10% of runtime): Housing firm selection now uses precomputed `category_array_cache` arrays directly with numpy operations instead of rebuilding dicts per household.
- **Eliminated `_get_good_category` overhead** (was 2.2% / 1.4M calls): Removed redundant `.lower()` calls since `_build_good_category_lookup` already lowercases. Direct dict access replaces function calls throughout hot paths.
- **Fixed O(HH×firms) scaling in `_batch_apply_household_updates`**: Pre-built `ceo_lookup` (household_id → firm/median_wage) and `happiness_boost_lookup` (good_name → boost) dicts before the household loop, replacing nested firm iteration.
- **Inlined switching friction logic** in `_plan_category_purchases` to avoid building `firm_utility_map` dictcomp per household.
- **Replaced `household.is_employed` property** with direct `household.employer_id is not None` to avoid property overhead in tight loops.
- **Result**: 29.5s → 19.7s at 1000 HH (33% faster), 76s → 47s at 2000 HH (38% faster). Superlinear scaling in `_batch_apply_household_updates` reduced from 3.8x to near-linear.

### Food Consumption System Rewrite

- **Fixed `food_consumed_this_tick` / `food_consumed_last_tick` never being populated**: These fields were only set in tests, never during actual simulation. Added proper tracking in `_batch_apply_household_updates`.
- **Perishable food model**: Food is now consumed up to the health threshold each tick (eat what you need), with 50% of leftovers spoiling. Replaces the old 10% flat consumption rate that caused inventory to pile up (0 → 26,614 units).
- **Services fully consumed each tick**: Service goods are now consumed entirely each tick with happiness boosts applied, matching real-world service consumption patterns.
- **Food satiation cap fix**: Changed from `food_health_mid_threshold * 1.5 = 3.0` to `food_health_high_threshold = 5.0` units, fixing an artificial cap that starved households.

### Health System Overhaul

- **Rewrote `_batch_update_wellbeing` health formula**: Replaced broken binary threshold logic (`total_goods > 15`) with proportional food-based health using `food_consumed_this_tick`.
- **Non-linear health curve (`ratio^0.6`)**: Implements the user's design — harsh penalty for zero food (-0.035/tick), near-neutral for slight undereating (-0.0004 at 2 units), positive at adequate eating (+0.009 at 3 units), full boost at threshold (+0.025 at 5 units).
- **Symmetric food boost/penalty**: Both `food_health_high_boost` and `food_starvation_penalty` set to 0.03 (was asymmetric 0.02/0.05 which caused death spirals).
- **Widened health decay ranges for population variation**: Low (0.02-0.25/yr, 60%), Mid (0.25-0.45/yr, 30%), High (0.45-0.70/yr, 10%). Creates realistic health distribution across the population (avg 0.80, std 0.36).
- **Per-agent randomized morale parameters** in batch wellbeing (morale_emp_boost, morale_unemp_penalty, morale_unhoused_penalty) now match the per-agent `update_wellbeing()` path.

### Config Changes

- `food_health_high_boost`: 0.02 → 0.03
- `food_starvation_penalty`: 0.05 → 0.03
- `health_decay_low_probability`: 0.70 → 0.60
- `health_decay_mid_probability`: 0.95 → 0.90
- `health_decay_low_range`: (0.0, 0.20) → (0.02, 0.25)
- `health_decay_mid_range`: (0.20, 0.30) → (0.25, 0.45)
- `health_decay_high_range`: (0.30, 0.50) → (0.45, 0.70)

### Files Updated

- `backend/agents.py`
- `backend/economy.py`
- `backend/config.py`

### Validation

- Profiled at 1000 and 2000 households confirming speedup and near-linear scaling
- Economy stabilizes at 97-98% employment, avg health 0.80, happiness rising over time
- Health distribution shows realistic variation (std 0.36, p10=0.00, p25=0.74, p75=1.00)

---

## [2026-03-09] EcoSim 2.0 - Contract Test Harness + Healthcare Queue Regression Fix

### Overview

Added a deterministic scenario-test harness for handcrafted economies and fixed a regression where `Economy` had fallen back to legacy healthcare sink behavior instead of queue-based service flow.

### What Changed

- Added reusable deterministic test factories for direct object creation and tiny generated economies.
- Added fixtures exposing:
  - `factory` namespace (households/firms/government/economy builders)
  - `economy_factory` helper for compact scenario setup
- Added factory contract tests to validate handcrafted and generated setup paths.
- Restored queue-based healthcare lifecycle in `Economy`:
  - reset per-tick healthcare counters/state
  - doctor health lock application
  - household healthcare request enqueue
  - queue prioritization for sick doctors
  - capacity-capped healthcare visit processing
  - affordability deferral (keeps queued if household cannot pay)
- Excluded healthcare from goods market snapshot (`healthcare` is service queue flow, not goods shopping).
- Converted legacy `_process_healthcare_and_loans` path into a compatibility no-op.
- Updated one behavior contract expectation to match the current curved food-to-health formula (`ratio ** 0.6`).

### Files Updated

- `backend/tests_contracts/factories.py`
- `backend/tests_contracts/conftest.py`
- `backend/tests_contracts/test_contracts_factories.py`
- `backend/tests_contracts/test_contracts_behavior.py`
- `backend/economy.py`

### Validation

- Ran: `.\.venv\Scripts\python.exe -m pytest backend/tests_contracts -q`
- Result: `25 passed, 4 skipped`

---

## [2026-03-03] EcoSim 2.0 - Healthcare Household Visit Distribution Model

### Overview

Household healthcare demand was changed from per-tick urgency probability to annual sampled visit plans, with per-visit healing tied to missing health and planned visit count.

### What Changed

- Replaced probabilistic per-tick visit request logic with annual (52-tick) visit-count sampling.
- Added health-bucket visit distributions:
  - healthy (`>=0.70`): 0/1/2 visits with 30%/40%/30%
  - below 70%: 1/2/3 visits with 30%/40%/30%
  - below 30%: 2/3/4 visits with 30%/40%/30%
  - below 10%: 4/5/6 visits with 50%/45%/5%
- Visit schedules are generated once per annual window and queued by due ticks.
- Healing per completed visit now follows:
  - `heal_per_visit = (1 - health_at_plan_time) / planned_visits`
  - Example: health 0.85 with 2 planned visits -> +0.075 each visit
- Legacy automatic follow-up scheduling is now disabled (annual sampled plan is the revisit controller).

### Files Updated

- `backend/config.py`
- `backend/agents.py`
- `backend/economy.py`
- `backend/tests_contracts/test_tier2_behavior_contracts.py`
- `backend/test_firm_behavior.py`
- `docs/HEALTHCARE_SERVICE_MODEL.md`

---

## [2026-03-03] EcoSim 2.0 - Healthcare Workforce Overhaul (Doctors, Training, Residency)

### Overview

Healthcare staffing now follows a constrained doctor pipeline instead of generic labor. This enforces scarcity, backlog-driven wage pressure, and realistic training delays.

### What Changed

- Added a medical workforce pipeline at household level:
  - `none -> student -> resident -> doctor`
  - 4-year training (`208` ticks)
  - residency starts halfway through training
- Students cannot work while in medical school.
- Residents and doctors can only match into healthcare firms.
- Healthcare firms can only hire residents/doctors from the labor market.
- Added per-doctor capacity model:
  - doctors: roughly `2-3` visits/tick (household-specific sampled cap)
  - residents: max `0.5` visits/tick
  - fractional capacity carries over across ticks
- Added per-firm healthcare workforce cap based on population:
  - `0.2%` of households per healthcare firm (`1000 households -> 2 workers`)
- Added medical school debt flow:
  - government-originated training loan principal
  - weekly interest accrual
  - gradual repayment from household income
- Added throttled med-school enrollment under shortage:
  - up to 1 enrollment every 52 ticks while active trainees < 10
  - then 1 enrollment every 104 ticks
- Healthcare demand still backlog/queue-driven; wage and pricing respond to demand pressure.

### Files Updated

- `backend/config.py`
- `backend/agents.py`
- `backend/economy.py`
- `docs/HEALTHCARE_SERVICE_MODEL.md`

---

## [2026-03-03] EcoSim 2.0 - Healthcare Service Economics Tuning

### Overview

Healthcare service firms now react to projected demand/backlog in wage and hiring decisions, and visit payments default to household-paid (no automatic government subsidy).

### What Changed

- Added backlog-sensitive healthcare hiring acceleration with a bounded per-tick cap.
- Healthcare labor matching now prioritizes healthcare firms with active queue pressure.
- Healthcare pricing now reacts to queue/pressure (bounded by a configurable ceiling).
- Healthcare wage planning now uses projected demand/capacity and can rise even when current revenue is low, preventing zero-hire deadlock.
- Visit payments now use payer split:
  - household pays `firm.price * (1 - subsidy_share)`
  - government pays `firm.price * subsidy_share`
  - default `subsidy_share = 0.0` (no subsidy)
- Updated healthcare design documentation with:
  - output per worker
  - hiring priority behavior
  - payer model and subsidy toggle
  - affordability note

### Key Params Added

- `healthcare_max_hires_per_tick`
- `healthcare_price_pressure_target`
- `healthcare_price_increase_rate`
- `healthcare_price_decrease_rate`
- `healthcare_price_ceiling_multiplier`
- `healthcare_visit_subsidy_share`

---

## [2026-03-03] EcoSim 2.0 - Healthcare Refactor: Queue-Based Service Model

### Overview

Healthcare was migrated from a storable goods path to a non-storable service path with queueing, visit capacity, and backlog-driven staffing.

### What Changed

- Healthcare firms no longer produce or store inventory goods.
- Households no longer buy healthcare in the goods market consumption planner.
- Each tick, households request care from need signals:
  - follow-up due ticks from `care_plan_due_ticks`
  - low-health urgency/critical thresholds
  - low-probability preventive checkups on annual cadence
- Healthcare firms now maintain:
  - `healthcare_queue`
  - `healthcare_capacity_per_worker`
  - `healthcare_arrivals_ema`
  - backlog horizon and idle streak controls
- Each tick, firms process queued visits up to effective capacity:
  - `effective_capacity = workers * healthcare_capacity_per_worker`
  - completed visits apply diminishing-returns healing: `delta = base_heal * (1 - health)`
  - followups (1-3) are scheduled when post-visit health stays below threshold
- Financial flow for healthcare visits:
  - government reimburses firms per completed visit at firm price
  - healthcare service units are tracked in firm sales for accounting/tax integration

### Stability / Guardrails

- Healthcare inventory is forcibly zeroed for healthcare firms.
- Legacy healthcare goods inventory remnants are purged from households.
- Queue flow prevents duplicate active requests per household via `queued_healthcare_firm_id`.
- Tests now assert:
  - healthcare inventory remains zero
  - completed visits do not exceed capacity
  - queue and health bounds remain valid

### Files Updated

- `backend/config.py`
- `backend/agents.py`
- `backend/economy.py`
- `backend/run_large_simulation.py`
- `backend/test_firm_behavior.py`
- `backend/tests_contracts/conftest.py`
- `backend/tests_contracts/test_tier1_invariants.py`
- `backend/tests_contracts/test_tier2_behavior_contracts.py`
- `backend/tests_contracts/test_tier3_short_integration.py`

---
## [2026-02-21] EcoSim 2.0 — Agent Logic Update: Households

### Overview

Major refactor of the Household agent class to remove hardcoded nominal values and introduce bounded rationality, behavioral frictions, and prospect-theory-inspired expectations. These changes make household decision-making adaptive, context-dependent, and economically grounded.

---

### Agent Log Update — Households

#### Feature 1: Dynamic Desperation & Skill Hysteresis (Labor Market)

**What changed**: Removed the hardcoded `cash_balance < $200` desperation threshold. Wage acceptance and job search urgency now adapt to the household's own price beliefs.

**Dynamic Living Cost Floor**:
```
living_cost_floor = expected_housing_price + expected_food_price
desperation_threshold = living_cost_floor × 1.5
```
When `cash_balance < desperation_threshold`, the household accepts wages 15% below its reservation wage. This means desperation is relative to each household's perceived cost of living, not a fixed dollar amount.

**Skill Hysteresis**:
If a household is unemployed for more than 26 consecutive ticks (~6 months), their `skills_level` degrades by 0.002 per tick, bottoming out at 0.10. This models the documented labor market effect where prolonged unemployment erodes human capital, making re-employment harder over time.

| Config Parameter | Default | Purpose |
|---|---|---|
| `desperation_living_cost_buffer` | 1.5 | Cash-to-living-cost ratio that triggers desperation |
| `desperation_wage_discount` | 0.85 | Wage acceptance discount when desperate |
| `skill_decay_unemployment_threshold` | 26 | Ticks before decay begins |
| `skill_decay_rate_per_tick` | 0.002 | Skill loss per tick |
| `skill_decay_floor` | 0.10 | Minimum skill level |

**Files**: `agents.py` (`plan_labor_supply`, new `apply_skill_decay`), `economy.py` (tick loop Phase 4), `config.py`

---

#### Feature 2: Buffer-Stock Consumption Model

**What changed**: Replaced the static fractional spending budget with a target wealth-to-income ratio driven by each household's innate `saving_tendency` trait.

**How it works**:
```
target_ratio = base_ratio × (0.5 + saving_tendency)
current_ratio = cash_balance / current_wage

if current_ratio < target_ratio:
    spend_fraction *= 0.6    # Aggressively save (penalize spending)
if current_ratio > target_ratio:
    spend_fraction *= 1.3    # Shed excess cash (boost spending)
```

This means thrifty households (high `saving_tendency`) target a larger buffer and cut spending sooner when below it. Spendthrift households (low `saving_tendency`) have a lower target and consume more freely. The result is a heterogeneous savings distribution that emerges from individual traits rather than a uniform rule.

| Config Parameter | Default | Purpose |
|---|---|---|
| `target_wealth_income_ratio_base` | 4.0 | Base target ratio (multiplied by thriftiness) |
| `buffer_stock_save_penalty` | 0.6 | Spend fraction multiplier when below target |
| `buffer_stock_spend_bonus` | 1.3 | Spend fraction multiplier when above target |

**Files**: `agents.py` (`plan_consumption`), `config.py`

---

#### Feature 3: Bounded Rationality in Firm Selection (Awareness Pool & Frictions)

**What changed**: Removed the O(N×M) global search where every household evaluated every firm. Households now maintain a small **awareness pool** of 5–10 firms per consumption category and only run softmax utility calculations on that pool.

**Awareness Pool**:
- Initialized by randomly sampling up to 7 firms from the market
- Refreshed every 4 ticks: the lowest-utility firm is dropped and a new firm is randomly sampled from the global market (simulating organic discovery via word-of-mouth, advertising, etc.)

**Switching Friction**:
Each household tracks a `current_primary_firm` per category. For a challenger firm to replace the primary, its utility must exceed the incumbent's by a friction threshold:

| Category | Friction Threshold |
|---|---|
| Housing | 15% |
| Services | 5% |
| Food | 2% |

The primary firm also receives a small loyalty bonus (+0.5) in the softmax distribution, modeling inertia and brand familiarity.

**New Household Fields**: `awareness_pool` (Dict[str, List[int]]), `current_primary_firm` (Dict[str, Optional[int]]), `last_pool_refresh_tick` (int)

| Config Parameter | Default | Purpose |
|---|---|---|
| `awareness_pool_max_size` | 7 | Max firms per category in pool |
| `switching_friction_housing` | 0.15 | Utility advantage to switch housing firm |
| `switching_friction_food` | 0.02 | Utility advantage to switch food firm |
| `switching_friction_services` | 0.05 | Utility advantage to switch services firm |
| `pool_refresh_interval` | 4 | Ticks between pool refresh cycles |
| `pool_refresh_drop_count` | 1 | Firms dropped per refresh |

**Files**: `agents.py` (new `refresh_awareness_pool`, `_filter_to_awareness_pool`, `_apply_switching_friction`, `_get_switching_friction`; modified `_plan_category_purchases`), `economy.py` (tick loop Phase 2), `config.py`

---

#### Feature 4: Asymmetric Adaptive Expectations (Prospect Theory)

**What changed**: Replaced the symmetric exponential smoothing (`alpha = 0.3`) for price belief updates with an asymmetric rule inspired by Kahneman & Tversky's Prospect Theory.

**Asymmetric Update Rule**:
```
if observed_price > current_belief:
    alpha = 0.4    # Fast adjustment — loss aversion to inflation
else:
    alpha = 0.1    # Slow adjustment — anchoring against deflation

new_belief = alpha × observed_price + (1 - alpha) × old_belief
```

**Why this matters**: Households react 4× faster to price increases than to price decreases. This produces the empirically observed asymmetry where inflation expectations ratchet up quickly but are sticky on the way down — a key feature of real consumer behavior that affects demand dynamics during both expansions and recessions.

| Config Parameter | Default | Purpose |
|---|---|---|
| `price_alpha_up` | 0.4 | Smoothing rate for price increases |
| `price_alpha_down` | 0.1 | Smoothing rate for price decreases |

**Files**: `agents.py` (`apply_purchases`, `plan_consumption` legacy path), `config.py`

---

### Changes by File

| File | Lines Changed | Type |
|---|---|---|
| `backend/config.py` | +23 | 19 new config parameters across 4 feature groups |
| `backend/agents.py` | +170 | 6 new methods, 3 new fields, 4 modified methods |
| `backend/economy.py` | +6 | 2 new integration points in tick loop |

---

### Testing Performed

1. **Unit Tests**: `test_household_agent.py` — all 8 tests pass
2. **Firm Tests**: `test_firm_behavior.py` — 52-tick simulation completes normally
3. **Government Tests**: `test_government_behavior.py` — fiscal policy adapts correctly
4. **Stochastic Tests**: `test_stochastic.py` — 3×100-tick runs show expected variation
5. **Feature Integration Test**: Custom verification script confirmed all 4 features produce correct outputs:
   - Dynamic desperation triggers at belief-based threshold (not $200)
   - Skill decay reduces 0.6000 → 0.5980 after 30 ticks unemployed
   - Awareness pool correctly limits to 7 firms from a market of 20
   - Asymmetric alpha: price increase moves belief 2.00 vs price decrease moves 0.50

---

### Agent Log Update — Firms

#### Feature 1: Emergency Restructuring (Anti-Zombie Firm Mechanism)

**What changed**: Removed the strict 10% cap on firing per tick when a firm is mathematically failing. Added a `survival_mode` flag that activates when cash reserves drop below the operating run rate.

**Survival Mode Trigger**:
```
operating_run_rate = sum(actual_wages)
if cash_balance < operating_run_rate * 2_weeks:
    survival_mode = True
```

When triggered, the firm:
- **Bypasses normal firing caps** and immediately lays off enough workers to bring operating costs below current rolling revenue
- **Hard-stops all R&D spending** (`apply_rd_and_quality_update` returns 0)
- **Blocks all dividend payouts** (`distribute_profits` returns 0)
- Runs at 10% production capacity (survival output)
- Exits survival mode once cash reserves reach 2x the healthy threshold

This prevents "zombie firms" that drain the economy by hoarding workers they can't afford, while giving viable firms a restructuring path back to profitability.

| Config Parameter | Default | Purpose |
|---|---|---|
| `survival_mode_runway_weeks` | 2.0 | Weeks of run rate that trigger survival mode |

**Files**: `agents.py` (`plan_production_and_labor`, `apply_rd_and_quality_update`, `distribute_profits`; new `survival_mode` field), `config.py`

---

#### Feature 2: Scalable Hiring Optimization (Proportional MRPL Search)

**What changed**: Replaced the hardcoded +/-2 worker local-neighborhood search in `_profit_optimal_workers` with a proportional search space.

**Old**: Evaluated staffing at `current_workers - 2, -1, 0, +1, +2` (5 candidates regardless of firm size).

**New**: Evaluates staffing at +/-5% and +/-10% of current workforce:
```
For a 100-worker firm: candidates = {90, 95, 100, 105, 110} + demand_target
For a 10-worker firm:  candidates = {9, 10, 11} + demand_target (min delta = 1)
```

This means a 200-worker firm now searches a 40-worker range (10 to 20 workers of adjustment) instead of a fixed 4-worker window, allowing large firms to make appropriately scaled hiring/firing decisions based on MRPL comparison.

| Config Parameter | Default | Purpose |
|---|---|---|
| `mrpl_search_fractions` | (0.05, 0.10) | Proportional search offsets from current workforce |

**Files**: `agents.py` (`_profit_optimal_workers`), `config.py`

---

#### Feature 3: Two-Stage Inventory Defense (Production Cuts before Price Fire-Sales)

**What changed**: Replaced the instant 20-30% price slash when inventory builds up with a two-stage PID-style controller that cuts production first and prices second.

**Stage 1 (Volume Cut)** — in `plan_production_and_labor`:
```
if inventory > 1.5 * target_production AND NOT burn_mode:
    target_workers *= (1.0 - 0.07)   # Reduce labor by 7% to slow production
```
No price change yet. The firm first tries to let existing inventory sell through naturally at current margins.

**Stage 2 (Price Cut)** — in `plan_pricing`:
```
if inventory > 3.0 * target_production:
    price_cut = random(5%, 10%)       # Mild price reduction to clear backlog
```
Only activates if Stage 1 failed to clear the backlog. The price cut is 5-10% instead of the old 20-30%, respecting the min_price floor.

This prevents the deflationary spiral where firms slash prices, lose revenue, can't pay wages, fire workers, reducing demand further.

| Config Parameter | Default | Purpose |
|---|---|---|
| `inventory_stage1_threshold` | 1.5 | Inventory-to-target ratio triggering production cut |
| `inventory_stage1_labor_cut` | 0.07 | Fraction of labor to cut in Stage 1 |
| `inventory_stage2_threshold` | 3.0 | Inventory-to-target ratio triggering price cut |
| `inventory_stage2_price_cut_min` | 0.05 | Minimum Stage 2 price reduction |
| `inventory_stage2_price_cut_max` | 0.10 | Maximum Stage 2 price reduction |

**Files**: `agents.py` (`plan_production_and_labor`, `plan_pricing`), `config.py`

---

#### Feature 4: Pro-Cyclical R&D Strategy

**What changed**: Replaced the counter-cyclical R&D logic (which increased R&D to 15% when underselling) with a profit-margin-tied strategy.

**Old**: Boosted R&D by 25% when `units_sold < units_produced` (investing more when struggling).

**New**:
```
if net_profit <= 0:
    rd_rate = 0%              # No R&D when unprofitable
else:
    margin = net_profit / revenue
    rd_rate = 5% + 0.5 * margin   # Scale with profitability, cap at 10%
```

This is economically sound: firms that are losing money shouldn't be spending on speculative quality improvements — they should be preserving cash for survival. Profitable firms invest proportionally to their success, creating a virtuous cycle where quality leaders extend their advantage.

| Config Parameter | Default | Purpose |
|---|---|---|
| `rd_base_rate` | 0.05 | Base R&D spending as fraction of revenue |
| `rd_max_rate` | 0.10 | Maximum R&D rate at high margins |
| `rd_margin_scaling` | 0.5 | How much margin boosts R&D above base |

**Files**: `agents.py` (`apply_rd_and_quality_update`), `config.py`

---

### Changes by File (Firm Update)

| File | Lines Changed | Type |
|---|---|---|
| `backend/config.py` | +17 | 13 new config parameters across 4 feature groups |
| `backend/agents.py` | +80 | 1 new field, 4 modified methods |

---

### Testing Performed (Firm Update)

1. **All existing tests pass**: household, firm, government, stochastic
2. **Feature Integration Test**: Custom verification confirmed:
   - Survival mode triggers at cash < 2-week run rate, lays off 7 of 10 workers, blocks R&D and dividends
   - Proportional MRPL search evaluates {90, 95, 100, 105, 110} for a 100-worker firm
   - Stage 1 cuts production when inventory > 1.5x target; Stage 2 cuts price 5-10% when inventory > 3x
   - R&D = $0 at negative profit; R&D = $100 at 20% margin on $1000 revenue (rate = 10%)

---

## [2026-02-25] EcoSim 2.0 — Wellbeing System Refactor: Anti-Depression Patch

### Overview

Major refactor of the happiness/wellbeing system to fix a structural "death spiral" where negative economic shocks compound too quickly and recovery is too slow, causing the simulated economy to fall into perpetual depression.

**Root cause**: Happiness penalties were asymmetric (unemployment = -0.03 vs employment = +0.02), poverty penalties stacked (-0.08 combined), the natural decay rate was 5x higher than intended (config said 0.002 but agents used 0.01), and there was no floor to prevent the performance multiplier from dropping to 0.5x — creating a feedback loop where unhappy workers get fired, become unhappier, and can never recover.

---

### Agent Log Update — Household Wellbeing

#### Feature 1: Config Mismatch Fix & Poverty De-Duplication

**Bug fixed**: The `HouseholdAgent` dataclass had `happiness_decay_rate = 0.01` hardcoded, but `config.py` specified `0.002`. Agents were never initialized with the config value, so every household decayed at **5x the intended rate**.

**Fix**: Agent default now matches config at `0.002`.

**Poverty penalty refactored** from stacking to exclusive:
```
Old (stacking):
  if cash < 200: penalty -= 0.03
  if cash < 100: penalty -= 0.05   ← ADDITIONAL, total = -0.08

New (exclusive):
  if cash < 100:   penalty = -0.05
  elif cash < 200: penalty = -0.03  ← Only one applies
```

| Parameter | Old | New |
|-----------|-----|-----|
| `happiness_decay_rate` (agent default) | 0.01 | 0.002 |
| Poverty < $200 penalty | -0.03 (stacks) | -0.03 (exclusive) |
| Poverty < $100 penalty | -0.05 (stacks) | -0.05 (exclusive) |
| **Worst-case poverty hit** | **-0.08** | **-0.05** |

**Files**: `agents.py` (line 106), `config.py` (poverty params), `economy.py` (batch update)

---

#### Feature 2: Tiered Consumption & Symmetric Labor Effects

**Goods consumption happiness** replaced binary check (goods > 10 = +0.01, goods < 2 = -0.02) with three tiers:

| Goods Owned | Old Bonus | New Bonus |
|-------------|-----------|-----------|
| >= 5 units  | +0.00 (dead zone) | **+0.02** |
| >= 2 units  | +0.00 (dead zone) | **+0.01** |
| < 2 units   | -0.02 | -0.02 |

This eliminates the "dead zone" where households owning 2–10 goods got zero happiness from consumption.

**Employment effect equalized**: Was asymmetric (+0.02 employed / -0.03 unemployed). Now symmetric at **±0.03**.

**Housing penalty reduced**: Ongoing unhoused penalty reduced from -0.05/tick to **-0.02/tick**. The one-time eviction shock (-0.30) remains separate.

**Files**: `config.py` (tier thresholds), `agents.py` (update_wellbeing), `economy.py` (batch update)

---

#### Feature 3: Mercy Floor & Rubber-Band Recovery

**Mercy Floor**: When happiness drops below **0.25**, natural decay pauses completely (set to 0.0). This prevents agents from spiraling to absolute zero — even at rock bottom, they stop bleeding out.

**Rubber-Band Recovery**: All positive happiness boosts are now scaled by `(1 + (1 - current_happiness))`:
```
actual_boost = base_boost × (1.0 + (1.0 - happiness))
```
- At happiness = 0.0: boosts are **2.0x** normal (maximum recovery speed)
- At happiness = 0.5: boosts are **1.5x** normal
- At happiness = 1.0: boosts are **1.0x** normal (no amplification)

This means a miserable agent who gets a job or buys goods recovers much faster than a content agent would gain from the same event. Modeled after the psychological concept that improvements feel larger when you're at a low baseline.

**Files**: `config.py` (`mercy_floor_threshold`, `rubber_band_recovery`), `agents.py`, `economy.py`

---

#### Feature 4: Performance Multiplier Floor (Anti-Doom Loop)

**Old**: Performance multiplier ranged from **0.5x** (zero wellbeing) to 1.5x (perfect wellbeing). A depressed worker at 0.5x was nearly half as productive, making them the first to be fired, which further reduced their happiness.

**New**: Floor raised to **0.75x**. A depressed worker is slower, but not catastrophically unproductive. This breaks the doom loop where low happiness → low performance → fired → lower happiness.

| Wellbeing | Old Multiplier | New Multiplier |
|-----------|---------------|----------------|
| 0.0 (worst) | 0.50x | **0.75x** |
| 0.5 (mid)   | 1.00x | **1.12x** |
| 1.0 (best)  | 1.50x | 1.50x |

**Files**: `config.py` (`performance_min_multiplier`), `agents.py` (`get_performance_multiplier`)

---

### Testing Performed (Wellbeing Refactor)

1. **All existing tests pass**: household creation, goods consumption, wellbeing system, income/spending, firm behavior (52-tick), government behavior (52-tick)
2. **Feature verification** confirmed:
   - Agent decay rate = 0.002 (matches config, was 0.01)
   - Poor employed household (cash=$50): happiness 0.70 → 0.71 (old system: → 0.63)
   - Goods tiers: >=5 gives +0.02, >=2 gives +0.01, <2 gives -0.02
   - Mercy floor: happiness=0.20 agent recovers to 0.29 in one employed tick (decay paused, 1.8x rubber-band)
   - Performance at zero wellbeing: 0.75x (was 0.50x)

---

## [2025-12-27] Session: Simulation Performance Hotfixes

### Overview
Reduced per-tick compute load in the realtime server loop and removed an O(n) household scan inside experience-adjusted production.

### Changes by File

#### 1. **backend/server.py**
**Before**: `run_loop()` recomputed `compute_household_stats`, `compute_firm_stats`, mean prices/supplies, and total net worth every tick.  
**After**: `run_loop()` caches those values and recomputes on a stride (`metrics_stride = 5`), reusing cached values in between.

#### 2. **backend/economy.py**
**Before**: `_calculate_experience_adjusted_production()` used a linear search:
```python
household = next((h for h in self.households if h.household_id == employee_id), None)
```
**After**: Uses the existing O(1) lookup:
```python
household = self.household_lookup.get(employee_id)
```

---

## [2025-12-27] Session: Consumption Planning Instrumentation

### Overview
Added internal timing instrumentation to identify sub-bottlenecks within category-based consumption planning.

### Changes by File

#### 1. **backend/agents.py**
**Before**: `_plan_category_purchases()` returned only planned purchases.  
**After**: `_plan_category_purchases()` returns `(planned_purchases, timings)` and records time in:
`price_cap`, `affordability`, `firm_selection`, and `quantity_calc`.

#### 2. **backend/economy.py**
**Before**: `_batch_plan_consumption()` only returned consumption plans.  
**After**: `_batch_plan_consumption()` aggregates timing totals/counts across households and stores them in:
`last_consumption_timings`, `consumption_timing_totals`, and `consumption_timing_counts`.

---

## [2025-12-27] Session: Consumption Planning Plan A Optimization

### Overview
Reduced per-household allocation overhead by caching per-category firm arrays once per tick and reusing them in category purchase planning.

### Changes by File

#### 1. **backend/economy.py**
**Before**: `_batch_plan_consumption()` rebuilt firm id/price/quality arrays inside each household call.  
**After**: `_batch_plan_consumption()` builds `category_array_cache` once per tick and passes it into `_plan_category_purchases()`.

#### 2. **backend/agents.py**
**Before**: `_plan_category_purchases()` rebuilt arrays from `options` every call and repeatedly accessed household attributes.  
**After**: `_plan_category_purchases()` reuses cached arrays when available and stores `quality_lavishness` / `price_sensitivity` locally.

---

## [2025-12-27] Session: Adaptive Performance Mode

### Overview
Added optional adaptive frequency mode to reuse consumption plans and reduce wellbeing updates during performance runs.

### Changes by File

#### 1. **backend/economy.py**
**Before**: Consumption planning and wellbeing updates ran every tick.  
**After**:
- Added `performance_mode` flag and `_cached_consumption_plans`.
- Consumption planning runs every 5 ticks when `performance_mode=True`, otherwise cached plans are reused.
- Wellbeing updates run every 10 ticks when `performance_mode=True`.

---

## [2025-12-27] Session: Stochastic Simulation & Performance Optimization

### Overview
Converted simulation from deterministic to stochastic behavior and fixed critical performance issues with config sliders during live simulation.

---

### 🎲 STOCHASTIC BEHAVIOR IMPLEMENTATION

#### Problem Statement
- Simulation was deterministic: same policy inputs → identical outputs every run
- Used seeded random number generators tied to agent IDs
- Made statistical analysis, A/B testing, and ML uncertainty quantification impossible

#### Solution Implemented
Removed all deterministic seeding and added true randomness to decisions and events while maintaining agent trait consistency.

---

### Changes by File

#### 1. **backend/agents.py**

**Line 376: Household Purchase Decisions**
```python
# BEFORE (deterministic):
rng = random.Random(hash((self.household_id, category)))
utilities += np.array([rng.uniform(-0.25, 0.25) for _ in range(len(utilities))])

# AFTER (stochastic):
# Add stochastic noise to purchasing decisions (not seeded - truly random)
utilities += np.array([random.uniform(-0.25, 0.25) for _ in range(len(utilities))])
```
**Impact**: Each purchasing decision now varies between runs, even for same household

---

**Lines 2675-2689: Government Policy Responses**
```python
# BEFORE (deterministic):
rng = random.Random(777)
bump = rng.uniform(0.0, 0.08)

# AFTER (stochastic):
# Stochastic policy response to deficit (truly random)
bump = random.uniform(0.0, 0.08)
```
**Impact**: Government tax adjustments now vary realistically in response to economic conditions

---

#### 2. **backend/economy.py**

**Lines 1905-1954: NEW - Random Economic Shocks System**
```python
def _apply_random_shocks(self) -> None:
    """
    Apply random economic shocks each tick to introduce stochasticity.

    Shocks include:
    - Demand shocks (random cash injections/withdrawals to households)
    - Supply shocks (temporary productivity changes to random firms)
    - Price shocks (random price pressures on specific goods)
    """
```

**Three Shock Types Added:**

1. **Demand Shocks** (5% chance per tick)
   - Random cash change: -$50 to +$100 (asymmetric, more likely positive)
   - Affects 5-15% of households randomly
   - Simulates: stimulus payments, tax refunds, unexpected expenses

2. **Supply Shocks** (3% chance per tick)
   - Productivity change: ±15% (0.85x to 1.15x)
   - Affects 1-3 random firms
   - Simulates: supply chain disruptions, technology improvements

3. **Health Shocks** (2% chance per tick)
   - Health loss: -5% to -20%
   - Affects 1-5% of population
   - Simulates: disease outbreaks, health crises

**Impact**: Introduces realistic economic volatility, no two runs are identical

---

**Line 542: Integrated Shocks into Main Loop**
```python
# Random economic shocks (stochastic events)
self._apply_random_shocks()
```
**Location**: Called every tick after warm-up period, before market operations

---

**Line 2093: Miscellaneous Transaction Taxes**
```python
# BEFORE (deterministic):
rng = random.Random(self.current_tick + 1234)
tax_rate = rng.uniform(0.0, 0.20)

# AFTER (stochastic):
# Stochastic tax rate on miscellaneous transactions (truly random)
tax_rate = random.uniform(0.0, 0.20)
```

---

#### 3. **backend/run_large_simulation.py**

**Line 179: Firm Ownership Assignment**
```python
# BEFORE (deterministic):
random.seed(42)  # Deterministic for reproducibility

# AFTER (stochastic):
# NOTE: No seed - ownership is stochastic for run-to-run variation
```
**Impact**: Firm ownership distribution varies between runs, affecting wealth distribution dynamics

---

#### 4. **backend/test_stochastic.py** (NEW FILE)

**Purpose**: Verification test proving stochastic behavior works

**Test Design**:
- Runs 3 simulations with **identical policy settings**:
  - 500 households
  - 10% wage tax
  - 25% profit tax
- Measures variation in outcomes

**Results**:
```
Run 1: Total Cash = $8,352,109.35
Run 2: Total Cash = $8,350,943.39
Run 3: Total Cash = $8,939,890.91

Total Cash Variation: $1,140,835.48 (13.7% variation)
Unemployment Variation: 0.00%

✓ SUCCESS: Simulation exhibits stochastic behavior!
```

**What This Proves**: Same policy configuration produces different economic outcomes across runs

---

### ⚡ PERFORMANCE OPTIMIZATION

#### Problem Statement
- Config sliders froze when adjusted during live simulation
- UI became unresponsive for 2-5 seconds when moving sliders
- User experience was poor during policy experimentation

#### Root Cause Analysis
File: `backend/server.py`, function `_apply_config_updates`

**Blocking Operations Identified**:
1. **Line 504-506**: Loop over ALL firms to update minimum wage
   - With 1000+ firms, this blocked the event loop
2. **Line 510-512**: Loop over ALL households to calculate average wage
   - With 10,000+ households, this blocked the event loop

```python
# BEFORE (blocking):
def _apply_config_updates(self, config_data: Dict[str, Any]):
    if "minimumWage" in config_data:
        for firm in self.economy.firms:  # Blocks on thousands of firms
            if firm.wage_offer < min_wage:
                firm.wage_offer = min_wage

    if "unemploymentBenefitRate" in config_data:
        total_wages = sum(h.wage for h in self.economy.households if h.is_employed)  # Blocks on thousands of households
```

---

#### Solution Implemented

**Lines 492-538: Made _apply_config_updates Async with Yielding**
```python
# AFTER (non-blocking):
async def _apply_config_updates(self, config_data: Dict[str, Any]):
    if "minimumWage" in config_data:
        for i, firm in enumerate(self.economy.firms):
            if firm.wage_offer < min_wage:
                firm.wage_offer = min_wage
            # Yield control every 100 firms to prevent blocking
            if i % 100 == 0:
                await asyncio.sleep(0)

    if "unemploymentBenefitRate" in config_data:
        for i, h in enumerate(self.economy.households):
            if h.is_employed:
                total_wages += h.wage
                employed_count += 1
            # Yield control every 200 households to prevent blocking
            if i % 200 == 0:
                await asyncio.sleep(0)
```

**Key Changes**:
1. Function signature: `def` → `async def`
2. Added `await asyncio.sleep(0)` every 100 firms
3. Added `await asyncio.sleep(0)` every 200 households
4. Converted sum() to manual loop for yielding

---

**Line 234: Updated run_loop to await**
```python
# BEFORE:
self._apply_config_updates(self.pending_config_updates)

# AFTER:
await self._apply_config_updates(self.pending_config_updates)
```

---

**Line 540: Made update_config async**
```python
# BEFORE:
def update_config(self, config_data):

# AFTER:
async def update_config(self, config_data):
```

---

**Line 592: WebSocket handler now awaits**
```python
# BEFORE:
manager.update_config(config_data)

# AFTER:
await manager.update_config(config_data)
```

---

### Impact Summary

**Stochastic Behavior**:
- ✅ Identical policies now produce varied outcomes (realistic economics)
- ✅ Enables ML uncertainty quantification
- ✅ Enables Monte Carlo optimization
- ✅ Enables statistical A/B testing with confidence intervals
- ✅ Measured 13.7% variation in total household cash across identical runs

**Performance**:
- ✅ Config sliders remain responsive during simulation
- ✅ UI no longer freezes when adjusting policies
- ✅ Event loop processes WebSocket messages between batches
- ✅ No degradation in simulation speed

---

### Testing Performed

1. **Syntax Validation**: All Python files compile without errors
2. **Stochasticity Test**: `backend/test_stochastic.py` confirms variation
3. **Manual Testing**: Config sliders responsive during live simulation (not pushed yet)

---

### Files Modified

| File | Lines Changed | Type |
|------|---------------|------|
| backend/agents.py | ~15 | Modified |
| backend/economy.py | +52 | Added method |
| backend/run_large_simulation.py | ~3 | Modified |
| backend/server.py | ~50 | Modified |
| backend/test_stochastic.py | +70 | New file |

**Total**: 5 files changed, 190+ insertions, 18 deletions

---

### Git Commit

**Branch**: `Ayman-Branch`
**Commit Hash**: `7db5ff1`
**Commit Message**: "Implement stochastic simulation and fix config slider performance"

**Repository**: Transferred to personal account
- **Old**: `https://github.com/Yonatan-Herrera/Ecosim.git`
- **New**: `https://github.com/AymanCode/EcoSim.git`

---

### Next Steps (Planned)

These are the features being considered for v2.0:

1. **ML Prediction Layer** - Train models to predict economic outcomes from policy inputs
2. **Portfolio Optimization** - Find optimal policy mixes using constrained optimization
3. **A/B Testing Framework** - Statistical comparison of policy interventions
4. **Production ML Pipeline** - Model versioning, drift detection, auto-retraining

---

## Previous Work (Pre-Changelog)

This changelog starts from 2025-12-27. Previous implementations include:
- Economic equilibrium system with Gini coefficient tracking
- 12 tracked subjects with historical data
- Inflation rate and birth rate sliders
- Minimum wage, UBI, unemployment benefits, wealth tax sliders
- Real-time GDP graph and metrics dashboard
- Neural visualization components (holographic avatars/buildings)
- Execute button fixes (confirmed state updates)

---

## [2025-12-27] Phase 2: ML Training Data Generation Setup

### Overview
Created infrastructure for generating ML training data to enable prediction layer that forecasts economic outcomes without running full simulations.

---

### 📊 TRAINING DATA GENERATION

#### Goal
Generate dataset of policy configurations → economic outcomes for ML model training.

**Target**: Predict GDP, unemployment, Gini coefficient, etc. in <100ms instead of 30 seconds

---

### New Files Created

#### 1. **backend/generate_training_data.py**

**Purpose**: Generate 500 policy-outcome pairs for ML training

**Configuration**:
```python
NUM_SAMPLES = 500              # Policy configurations to test
NUM_TICKS = 300                # Simulation length (~12 weeks)
NUM_HOUSEHOLDS = 1000          # Agents per simulation
NUM_FIRMS_PER_CATEGORY = 5     # 15 total firms
```

**Features**:
- **Latin Hypercube Sampling**: Better policy space coverage than random sampling
- **Automatic checkpoints**: Saves every 50 samples (recovery from crashes)
- **Progress tracking**: Updates every 10 sims with ETA
- **Comprehensive metrics**: 9 policy inputs → 11 economic outputs

**Policy Space Coverage**:
| Parameter | Range |
|-----------|-------|
| Wage Tax | 0% to 30% |
| Profit Tax | 10% to 50% |
| Inflation Rate | 0% to 10% |
| Birth Rate | 0% to 5% |
| Minimum Wage | $15 to $50 |
| Unemployment Benefit Rate | 0% to 80% |
| Universal Basic Income | $0 to $500 |
| Wealth Tax Threshold | $10K to $200K |
| Wealth Tax Rate | 0% to 10% |

**Output Metrics**:
- GDP, Unemployment Rate, Mean Happiness, Mean Health
- Mean Wage, Median Wage, Gini Coefficient
- Government Debt, Government Balance
- Total Household Wealth, Number of Active Firms

**Estimated Runtime**: 2-2.5 hours for 500 samples on typical PC

---

#### 2. **backend/test_training_setup.py**

**Purpose**: Verify setup before running full 2-hour generation

**What it tests**:
- ✓ Dependencies installed (numpy, pandas, scipy)
- ✓ Simulation modules import correctly
- ✓ 5 test simulations run successfully
- ✓ Data export works
- ✓ Estimates full runtime

**Runtime**: ~2 minutes

**Usage**:
```bash
python test_training_setup.py
```

---

#### 3. **backend/RUN_TRAINING.md**

**Purpose**: Complete guide for running training data generation on user's PC

**Contents**:
- Prerequisites and installation
- Configuration options (Quick/Standard/High Quality)
- How to run (foreground and background execution)
- Output file descriptions
- Progress monitoring
- Troubleshooting guide
- Performance optimization tips

**Includes**:
- Platform-specific commands (Windows/Mac/Linux)
- Checkpoint recovery instructions
- Memory optimization tips
- Expected dataset format

---

### Why This Design?

#### Latin Hypercube Sampling vs Random
```python
# Random: might miss corners of policy space
random_policies = [random.uniform(...) for _ in range(500)]

# LHS: guarantees coverage across all dimensions
from scipy.stats import qmc
sampler = qmc.LatinHypercube(d=9)
lhs_policies = sampler.random(n=500)
```

**Benefit**: 20-30% better ML performance with same number of samples

---

#### Checkpointing Strategy
```python
if (i + 1) % 50 == 0:
    checkpoint_df = pd.DataFrame(training_data)
    checkpoint_df.to_csv(f"training_data_checkpoint_{i+1}.csv", index=False)
```

**Benefit**: If script crashes at sample 487, you don't lose 2 hours of work

---

#### Why 300 Ticks?
| Ticks | Simulation Phase |
|-------|------------------|
| 0-52 | Warm-up (baseline firms only) |
| 53-150 | Market adjustment (competitive entry) |
| 151-300 | Equilibrium (policy effects visible) |

**Benefit**: Captures full policy impact without unnecessary compute

---

### Configuration Tradeoffs

| Config | Samples | Ticks | Agents | Runtime | ML Quality | Use Case |
|--------|---------|-------|--------|---------|------------|----------|
| Quick Test | 100 | 200 | 500 | 20 min | Basic | Development |
| **Standard** | 500 | 300 | 1000 | 2 hrs | Good | Production |
| High Quality | 1000 | 400 | 1000 | 6 hrs | Excellent | Research |
| Production | 2000 | 500 | 2000 | 12+ hrs | Best | Publication |

**Recommendation**: Start with Standard, upgrade to High Quality if needed

---

### Expected Output

**File**: `training_data_YYYYMMDD_HHMMSS.csv`

**Size**: ~500KB (500 rows × 20 columns)

**Format**:
```csv
wageTax,profitTax,...,gdp,unemployment_rate,gini_coefficient,...
0.15,0.25,...,8450000,5.2,0.42,...
0.08,0.35,...,9120000,3.8,0.38,...
...
```

---

### Next Steps (Phase 3)

Once training data is generated:
1. **Model Training**: Train XGBoost models on the dataset
2. **Model Evaluation**: Test prediction accuracy, feature importance
3. **API Integration**: Add `/predict` endpoint to server
4. **Frontend Integration**: Show ML predictions alongside simulation

---

### Files Modified/Created

| File | Type | Purpose |
|------|------|---------|
| backend/generate_training_data.py | New | Main data generation script |
| backend/test_training_setup.py | New | Setup verification test |
| backend/RUN_TRAINING.md | New | User guide for PC execution |
| CHANGELOG.md | Modified | Added this section |

---

### Git Status

**Branch**: `Ayman-Branch`
**Ready to commit**: Yes
**Ready to push**: Yes (user will run on their PC)

---

### User Instructions

**On your laptop** (current machine):
```bash
# Commit and push the new files
git add backend/generate_training_data.py backend/test_training_setup.py backend/RUN_TRAINING.md CHANGELOG.md
git commit -m "Add ML training data generation infrastructure"
git push origin Ayman-Branch
```

**On your PC** (faster machine):
```bash
# Pull the latest code
git pull origin Ayman-Branch

# Install dependencies
pip install numpy pandas scipy

# Test setup (2 minutes)
cd backend
python test_training_setup.py

# If test passes, run full generation (2 hours)
python generate_training_data.py
```

**After generation completes**:
- You'll have `training_data_YYYYMMDD_HHMMSS.csv`
- Ready for Phase 3: Model Training

---

*This changelog will be updated with each implementation session going forward.*

# Handoff — Bandit Routing for Speculative Decoding (m.krylov)

> Branch `research/m.krylov`, HEAD `107b65b`
> Working tree: 1 modified file (bandit_routing.py — uncommitted fixes)
> Single implementation file: `experiments/bandit_routing.py` (1903 lines)

---

## Status: Phase 5 — Exploration Sweep (RUNNING)

- **Phase 1–4**: ✅ Complete (UCB1, Thompson, LinUCB, per-arm distillation, multi-dataset, MLP comparison)
- **Phase 5**: ✅ Exploration parameter sweep implemented and smoke-tested
- **Blockers resolved**: `_preloaded_drafters` AttributeError fixed; CUDA OOM avoided via `--tiny` flag
- **Known issues**: Summary table shows zeros for sweep experiments (metrics nested under `exploration_sweep` key); convergence detection unreliable at `n < window_size`

---

## 1. What this does

Replaces the static MLP drafter-router (`09_+routing`) with **online multi-armed bandit** algorithms that learn which drafter to pick per prompt from live decoding performance — no separate training phase required.  Three bandit families are implemented (UCB1, Thompson Sampling, LinUCB), each optionally combined with **per-arm online distillation** so drafters improve while the router learns.

### Reward

Computed once per prompt (aggregated over all decode steps in that prompt):

```
reward = total_accepted_tokens / max(total_wall_time_ms / 1000, 1e-6)    # tokens/sec
```

Balances quality (acceptance count) against speed (wall-clock time).  A fast but inaccurate drafter and an accurate but slow drafter are both penalised.

### Data flow per prompt

```
prompt input_ids
    ↓
router.select_drafter(input_ids)  ← bandit (or LinUCB with features)
    ↓
selected drafter generates K tokens
    ↓
target verifies in 1 forward pass
    ↓
accepted tokens emitted, bonus residual sampled
    ↓
reward computed from StepResult list
    ↓
router.update(reward)
    ↓
[if distillation enabled, every replay_every prompts]
    → PerArmBuffer.sample_for_arm(arm_idx) → distiller.step()
```

---

## 2. Router algorithms (3)

All routers use a **round-robin initial exploration** phase (each arm selected once via `_round_robin_count`) before switching to their algorithm-specific selection.

### UCB1 — `UCBBanditRouter`

```
score(arm) = mean_reward + c * sqrt(ln(total_pulls) / arm_pulls)
```

Deterministic.  One hyperparameter `c` (default 2.0).

### Thompson Sampling — `ThompsonSamplingRouter`

Normal-Gamma conjugate posterior per arm.  Maintains sufficient statistics (N, Σr, Σr²) inside `_GaussianArm` and samples a posterior mean for each arm; picks the highest sample.  Fixed RNG seed 42 for reproducibility.  Prior: μ₀=0, κ₀=1, α₀=1, β₀=1.

Updates both the `_GaussianArm` posterior and the `DrafterEntry` (for sliding-window support).

### LinUCB (contextual) — `ContextualBanditRouter`

Each arm maintains a ridge-regression weight vector θ ∈ ℝᵈ (d=8 by default).  Score = θᵀx + α·√(xᵀA⁻¹x).  Updated via Cholesky rank-1 update with direct-inverse fallback.

**Feature vector** (from `_extract_prompt_features`), L2-normalised:

| # | Feature |
|---|---|
| 0 | log(prompt_length + 1) |
| 1 | vocab diversity (unique / total) |
| 2 | mean token ID / **vocab_size** |
| 3 | std token ID / **vocab_size** |
| 4 | fraction tokens < 100 (special/control) |
| 5 | fraction tokens 100–1000 (common) |
| 6 | fraction tokens 1000–5000 (medium) |
| 7 | fraction tokens ≥ 5000 (rare) |

Features 2–3 use the **actual model vocab_size** read from `ctx.drafter.model.config.vocab_size` at build time (e.g. ~50k for OPT, ~151k for Qwen2.5), not a hardcoded proxy.

---

## 3. DrafterEntry — sliding reward window

`DrafterEntry` is the bandit arm dataclass.  When `reward_window > 0` it maintains a FIFO `deque` of the most recent N rewards.  `mean_reward` is computed from the window instead of all history, so the bandit can **adapt when drafter quality changes** (e.g. during online distillation).

```python
entry = DrafterEntry(name="model", model=model, reward_window=32)
entry.record_reward(reward)  # use this, not direct field mutation
mean = entry.mean_reward     # windowed or full-history depending on reward_window
```

---

## 4. Per-arm distillation

Each drafter has its own `OnlineDistiller` + Adam optimiser.  A `PerArmBuffer` (FIFO, capacity 4096) tags every training entry with the arm index so each drafter trains **only on data it generated**.  Replay happens every 32 prompts, batch size 8.

`PerArmBuffer` uses a **seeded RNG** (`torch.Generator`, seed from config defaulting to 42) so `sample_for_arm()` produces reproducible results across runs.

Distillation loss (from `core/distillation/online.py`):

```
L = KL(target_in_drafter_space || drafter) + λ · NLL(drafter on accepted tokens)
```

---

## 5. Reward update granularity

Two modes controlled by `per_step_update` on `BanditRoutingExperiment`:

| Mode | Method | Updates per prompt |
|---|---|---|
| Per-prompt (default) | `_update_per_prompt()` | 1 (reward aggregated over all steps) |
| Per-step | `_update_per_step()` | N (one per decode step within the prompt) |

Per-step mode gives finer-grained learning signals at the cost of more frequent bandit updates.

---

## 6. Experiment classes (11, auto-discovered)

All classes are in `bandit_routing.py` and exported via `__all__`.  Discovery happens through `experiments/suites.py::discover_research_experiments()` which scans `research/*/experiments/*.py`.

| Class | Meta name | Algorithm | Distillation | Notes |
|---|---|---|---|---|
| `BanditUCBExperiment` | `bandit_ucb` | UCB1 | no | baseline bandit |
| `BanditThompsonExperiment` | `bandit_thompson` | Thompson | no | Bayesian baseline |
| `BanditUCBDistillExperiment` | `bandit_ucb_distill` | UCB1 | yes | per-arm distillation |
| `BanditThompsonDistillExperiment` | `bandit_thompson_distill` | Thompson | yes | per-arm distillation |
| `BanditContextualExperiment` | `bandit_contextual` | LinUCB | no | 8 prompt features, vocab_size-aware |
| `BanditContextualDistillExperiment` | `bandit_contextual_distill` | LinUCB | yes | contextual + distillation |
| `BanditVsMLPExperiment` | `bandit_vs_mlp_ucb` | UCB1 | no | head-to-head vs MLP (see §7) |
| `BanditVsMLPThompsonExperiment` | `bandit_vs_mlp_thompson` | Thompson | no | head-to-head vs MLP |
| `BanditMultiDatasetExperiment` | `bandit_multidataset_ucb` | UCB1 | no | gsm8k, mbpp, alpaca, xsum |
| `BanditMultiDatasetThompsonExperiment` | `bandit_multidataset_thompson` | Thompson | no | cross-dataset Thompson |
| `BanditExplorationSweepExperiment` | `bandit_exploration_sweep` | UCB1 + LinUCB | no | sweeps exploration params (see §14) |

### Inheritance

```
BaseExperiment
  └── BanditRoutingExperiment          (core logic: reward, buffer, distill hooks)
        ├── BanditUCBExperiment
        ├── BanditThompsonExperiment
        ├── BanditUCBDistillExperiment
        ├── BanditThompsonDistillExperiment
        ├── BanditContextualExperiment  (overrides build_router → LinUCB)
        │     └── BanditContextualDistillExperiment
        ├── BanditVsMLPExperiment       (overrides build_router → DualRouter)
        │     └── BanditVsMLPThompsonExperiment
        ├── BanditMultiDatasetExperiment
        │     └── BanditMultiDatasetThompsonExperiment
        └── BanditExplorationSweepExperiment  (overrides build_router + run → sweep loop)
```

---

## 7. DualRouter — bandit vs MLP comparison

The `BanditVsMLPExperiment` needs to record what the MLP router would have chosen **and** what the bandit chose, then compare.  The challenge: the experiment hook `on_decode_step` does not receive `input_ids`, but the MLP router needs them to embed and select.

### Solution: `DualRouter` wrapper

The runner calls `router.select_drafter(input_ids)` once per prompt — this is the only point where `input_ids` is available.  `DualRouter.select_drafter()`:

1. Caches `input_ids` in `_last_input_ids` for later MLP observation recording
2. Asks the MLP router → records its index in `_mlp_selection`
3. Asks the bandit router → returns its selection for actual decoding
4. `update(reward)` is forwarded to the bandit router only

### Online MLP training

The MLP router starts with random weights.  `DualRouter` trains it **online** every `mlp_train_every` updates (default 32):

- `BanditVsMLPExperiment.on_decode_step()` calls `router.mlp.record(input_ids, drafter_idx, acceptance_rate)` to feed observations to the MLP's training buffer
- `DualRouter.update()` calls `mlp.train_router(n_epochs=10, lr=1e-3)` every 32 updates (when ≥ 4 samples accumulated)

This means the MLP learns from actual decoding performance during the run rather than staying at random initialisation.

### Comparison metrics

In `on_after_decode`, the experiment computes:

- `bandit_arm_distribution` / `mlp_arm_distribution` — per-router selection counts
- `agreements` / `disagreements` — how often both chose the same drafter
- `bandit_router` / `mlp_router` — full per-router `.stats()` output
- `mlp_online_train_count` — number of online training rounds completed

---

## 8. Configuration parameters

### BanditRoutingExperiment (base)

| Parameter | Default | Description |
|---|---|---|
| `algorithm` | `"ucb"` | `"ucb"`, `"thompson"` (LinUCB via subclass) |
| `exploration` | 2.0 | UCB `c` or LinUCB `α` |
| `enable_distillation` | False | Enable per-arm online distillation |
| `buffer_capacity` | 4096 | PerArmBuffer max entries |
| `replay_every` | 32 | Distillation replay frequency (prompts) |
| `replay_batch` | 8 | Distillation batch size |
| `reward_window` | 0 | Sliding window size (0 = all history) |
| `per_step_update` | False | Per-step vs per-prompt bandit updates |

### DualRouter

| Parameter | Default | Description |
|---|---|---|
| `mlp_train_every` | 32 | Train MLP every N updates |
| `mlp_train_epochs` | 10 | MLP training epochs per round |
| `mlp_train_lr` | 1e-3 | MLP training learning rate |

### DrafterEntry

| Parameter | Default | Description |
|---|---|---|
| `reward_window` | 0 | Sliding reward window size (0 = disabled) |

### PerArmBuffer

| Parameter | Default | Description |
|---|---|---|
| `capacity` | 4096 | Max buffer entries |
| `seed` | 42 | RNG seed for reproducible sampling |

### ContextualBanditRouter

| Parameter | Default | Description |
|---|---|---|
| `exploration` | 1.0 | LinUCB α (exploration coefficient) |
| `n_features` | 8 | Feature vector dimension |
| `vocab_size` | 50257 | Model vocab size for feature normalisation |

---

## 9. How to run

```bash
# List all research experiments
python src/main.py --list --research

# Single experiment (tiny models, 10 samples)
python src/main.py --experiment bandit_ucb --tiny -n 10

# All research experiments (tiny)
python src/main.py --research --tiny -n 5

# Bandit vs MLP comparison
python src/main.py --experiment bandit_vs_mlp_ucb --tiny -n 20

# Contextual bandit
python src/main.py --experiment bandit_contextual --tiny -n 10

# Multi-dataset sweep
python src/main.py --experiment bandit_multidataset_ucb --tiny -n 100

# With sliding reward window (non-stationary)
# (set via subclass constructor or experiment config override)
```

### Default models

```
drafter_model_paths = ["Qwen/Qwen2.5-0.5B-Instruct", "Qwen/Qwen2.5-1.5B-Instruct"]
target_model_path   = "Qwen/Qwen2.5-7B-Instruct"
dataset             = "gsm8k"
max_samples         = 500
max_new_tokens      = 128
```

`--tiny` overrides to `opt-125m` / `opt-350m` for fast iteration.

---

## 10. Metrics produced

Always (standard): `acceptance_rate`, `tokens_per_sec`, `gpu_mem_peak_gb`, `gpu_mem_mean_gb`, `wall_time_total_s`, `wall_time_mean_s`.

Bandit-specific (via `on_extra_metrics`):

| Key | Type | Description |
|---|---|---|
| `bandit_router` | dict | Algorithm, exploration params, per-arm pulls/means |
| `bandit_mean_reward` | float | Mean reward across all prompts |
| `bandit_std_reward` | float | Std dev of rewards |
| `mean_wall_time_ms` | float | Average decode step wall time |
| `buffer_stats` | dict | Total entries + per-arm breakdown (distillation only) |
| `bandit_vs_mlp_comparison` | dict | Agreement counts, arm distributions, online train count (vs-MLP only) |
| `per_dataset_metrics` | dict | Per-dataset reward stats + arm distributions (multi-dataset only) |

---

## 11. Remaining open questions

1. **Exploration vs exploitation trade-off** — ✅ Initial sweep completed (see §14).  UCB `c=0.1` is best at small sample sizes.  Larger sweeps (`n ≥ 50`) needed for convergence analysis.

2. **UCB vs Thompson comparison** — Run both on the same dataset with the same seed and compare convergence speed, final reward, and arm distribution.  The experiments exist but the comparison has not been executed.

3. **Distillation tuning** — Optimal `replay_every` and `replay_batch` values depend on dataset and drafter sizes; needs empirical tuning.  Current defaults (32, 8) are placeholders.

4. **Multi-dataset humaneval** — Currently covers gsm8k, mbpp, alpaca, xsum.  humaneval is not yet in `BanditMultiDatasetExperiment.DATASETS`.

5. **Non-stationary reward analysis** — With `reward_window > 0`, how do policies behave when drafters improve mid-run?  Standard bandit regret bounds don't apply.  Needs empirical study.

6. **Summary table display** — `BanditExplorationSweepExperiment` nests metrics under `exploration_sweep`, so the CLI summary table shows zeros.  The JSON output is correct.  Fix: either flatten top-level `best_overall` metrics or special-case the sweep experiment in `_print_summary`.

7. **Convergence detection at small n** — `_find_convergence()` requires `n ≥ convergence_window` (default 5).  With `-n 5`, convergence is always `None`.  Consider lowering the window or reporting "not yet converged" explicitly.

---

## 12. Key non-experiment classes

| Class | Role |
|---|---|
| `DrafterEntry` | One bandit arm: name, model, pulls, total_reward, sliding window |
| `_GaussianArm` | Normal-Gamma posterior internals for Thompson Sampling |
| `_LinUCBArm` | Ridge-regression posterior for one LinUCB arm |
| `PerArmBuffer` | FIFO buffer tagged by arm index; seeded `sample_for_arm()` |
| `BufferEntry` | One training example (logits, tokens, mask, arm_index) |
| `DualRouter` | Wrapper that runs bandit + MLP router in parallel with online MLP training |

---

## 13. Files

```
research/m.krylov/
├── README.md                        # Research hypothesis, phased plan, task checklist
├── HANDOFF.md                       # This file
└── experiments/
    ├── __init__.py                  # Docstring only (discovery uses __all__ from bandit_routing.py)
    └── bandit_routing.py            # Everything: routers, buffer, 11 experiment classes (1903 lines)
```

No other files in this research directory are modified or created by this work.  All router algorithms, buffers, and experiments live in the single `bandit_routing.py` module.  The MLP routing components (`DynamicRouter`, `RouterModel`, `DrafterSpec`) are imported from `src/core/extensions/routing/router.py`.

## 14. Exploration Sweep Results (smoke test)

**Command**: `python src/main.py --experiment bandit_exploration_sweep --tiny -n 5 --no-mlflow`
**Config**: `opt-125m` vs `opt-350m` as drafters, `opt-350m` as target, gsm8k, 5 samples, 32 max tokens.

### UCB sweep

| c value | mean_reward | acceptance_rate | tokens_per_sec | arm distribution |
|---------|-------------|-----------------|----------------|-------------------|
| 0.1 | 362.6 | 70.8% | 8.35 | opt-350m: 4/5, opt-125m: 1/5 |
| 0.5 | 315.9 | 64.2% | 9.05 | opt-350m: 4/5, opt-125m: 1/5 |
| 1.0 | 310.2 | 63.4% | 7.94 | opt-350m: 4/5, opt-125m: 1/5 |
| 2.0 | 250.2 | 55.0% | 7.26 | opt-350m: 4/5, opt-125m: 1/5 |
| 5.0 | 256.5 | 55.9% | 8.41 | opt-125m: 3/5, opt-350m: 2/5 |

### LinUCB sweep

| α value | mean_reward | acceptance_rate | tokens_per_sec | arm distribution |
|---------|-------------|-----------------|----------------|-------------------|
| 0.1 | 345.7 | 68.4% | 7.67 | opt-350m: 4/5, opt-125m: 1/5 |
| 1.0 | 293.8 | 61.1% | 8.14 | opt-350m: 4/5, opt-125m: 1/5 |
| 5.0 | 273.7 | 58.3% | 8.37 | opt-350m: 4/5, opt-125m: 1/5 |

### Key observations

- **Low exploration wins at small n**: Both UCB and LinUCB with `c/α=0.1` achieve highest mean reward because round-robin exploration (1 pull each) + greedy exploitation quickly identifies `opt-350m` as superior.
- **High exploration hurts**: At `c=5.0`, UCB explores `opt-125m` more (3/5 pulls), reducing mean reward by 29%.
- **LinUCB is more conservative**: Even at `α=5.0`, LinUCB still picks `opt-350m` 4/5 times because the contextual features reinforce the same arm choice.  UCB at `c=5.0` is more randomized.
- **No convergence detected**: All `convergence_sample = null` because `n=5` equals `convergence_window=5`, so only a single index is checked (and round-robin pollutes the first entries).
- **Best overall**: `ucb_0.1` with mean_reward=362.6, acceptance_rate=70.8%.

### Uncommitted fixes in `bandit_routing.py`

Two bugs fixed but not yet committed:

1. **`_preloaded_drafters` AttributeError** — `build_router()` referenced `self._preloaded_drafters` but it was never initialized.  Fixed by initializing the dict in `run()` after `runner._build_models()` and before the sweep loop.
2. **Primary drafter not routed correctly** — `build_router()` used `_preloaded_drafters.get(path)` for all paths, missing the runner-loaded primary drafter.  Fixed by checking `path == cfg.drafter_model_path` and falling back to `ctx.drafter`.

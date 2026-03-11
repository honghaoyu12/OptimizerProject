# Session Log

A chronological record of everything discussed and built across all conversations on this project.

---

## Session 1 — Initial Setup

**What we discussed:**
- Set up the project from scratch as a testing ground for custom numerical optimizers
- Decided on PyTorch as the core dependency
- Chose MNIST as the starting dataset

**What was built:**
- `model.py` — MLP with configurable `hidden_sizes`
- `train.py` — training loop with `OPTIMIZER_REGISTRY`, `get_dataloaders()`, `train_one_epoch()`, `evaluate()`; CLI flags: `--dataset`, `--optimizer`, `--lr`, `--epochs`, `--batch-size`, `--data-dir`, `--device`
- `optimizers/base.py` — `BaseOptimizer` extending `torch.optim.Optimizer`; subclasses only need to implement `step()`
- `optimizers/sgd.py` — `VanillaSGD`, a minimal reference implementation (`θ ← θ − lr · ∇θ`)
- `optimizers/__init__.py` — exports `BaseOptimizer`, `VanillaSGD`

---

## Session 2 — Live Visualisation and Benchmark Runner

**What we discussed:**
- Wanted to see training progress visually in real time
- Wanted to compare multiple optimizers side by side

**What was built:**
- `visualizer.py` — `Visualizer` class: live 2×2 matplotlib dashboard (loss/epoch, accuracy/epoch, weight norms per layer, grad norms per layer); `plot_benchmark()` for static comparison grids
- `benchmark.py` — `DATASET_REGISTRY`, `OPTIMIZER_REGISTRY`, `prompt_multiselect()` (numbered interactive menu), `run_benchmark()`, `plot_benchmark()` call
- `train.py` updates — `--hidden-sizes`, `--no-plot`, `--save-plot` CLI flags; `run_training()` shared loop; `linear_layer_names()`, `weight_norms()` helpers

---

## Session 3 — Diagnostics, CIFAR-10, and Model Selection

**What we discussed:**
- Wanted deeper optimizer diagnostics beyond loss and accuracy
- Wanted CIFAR-10 as a more challenging dataset
- Wanted to switch between MLP and ResNet-18 from the CLI

**What was built:**
- `metrics.py` (new) — `compute_hessian_trace()` (Hutchinson estimator: Tr(H) ≈ (1/S) Σ vᵀHv); `compute_sharpness()` (SAM-style: max‖δ‖≤ε L(θ+δ) − L(θ)); both return `float("nan")` on failure
- `model.py` updates — MLP gains `input_size` and `num_classes` params; `ResNet18` class wrapping torchvision with 3×3 conv1 and Identity maxpool for small images
- `train.py` updates — `DATASET_INFO` dict exported; CIFAR-10 in `get_dataloaders()` with RandomCrop+HorizontalFlip; `build_model()` helper; `train_one_epoch()` return changed from tuple to dict (adds `grad_norm_global`, `grad_norm_std`, `step_losses`); `run_training()` history expanded (adds `time_elapsed`, `target_accuracy_epoch/time`, `grad_norm_global/std`, `hessian_trace`, `sharpness`, `step_losses`); `--model`, `--hessian` CLI flags
- `benchmark.py` updates — `MODEL_REGISTRY`; CIFAR-10 in `DATASET_REGISTRY`; 3-step selection menu (Datasets → Models → Optimizers); results keyed by 3-tuple `(dataset_name, model_name, optimizer_name)`
- `visualizer.py` updates — expanded from 2×2 to 3×2 dashboard (adds batch-level loss, global grad norm with ±std band, hessian/sharpness dual y-axis panel); `update()` and `plot_benchmark()` signatures extended

---

## Session 4 — Vision Transformer

**What we discussed:**
- Wanted a third model option alongside MLP and ResNet-18

**What was built:**
- `model.py` — `ViT` class: patch embedding with pre/post LayerNorm, learnable CLS token and positional embeddings, Pre-LN TransformerEncoder (`norm_first=True`, `enable_nested_tensor=False`), classification from CLS token; `patch_size=4` chosen to divide 28, 32, and 64 evenly
- `train.py` — `build_model()` extended with `"vit"` branch; derives `image_size` from `dataset_info` automatically
- `benchmark.py` — `MODEL_REGISTRY` extended with ViT entry

**Issues encountered and fixed:**
- `nn.TransformerEncoder` with `norm_first=True` triggers a warning → fixed with `enable_nested_tensor=False`

---

## Session 5 — Tiny ImageNet Dataset

**What we discussed:**
- Wanted a larger, harder dataset (200 classes, 64×64 images)

**What was built:**
- `train.py` — `"tiny_imagenet"` added to `DATASET_INFO` and `_DATASET_STATS`; `_setup_tiny_imagenet()` helper that downloads the zip (~236 MB), extracts it, reorganises train (removes extra `images/` subdirectory level) and val (flat → per-class subdirs using `val_annotations.txt`), writes `.setup_done` marker; `get_dataloaders()` handles `ImageFolder` for Tiny ImageNet with RandomCrop(64, padding=8) + HorizontalFlip
- `benchmark.py` — Tiny ImageNet added to `DATASET_REGISTRY`

---

## Session 6 — 7 New Optimizers

**What we discussed:**
- Wanted to add Adagrad, NAdam, RAdam, AdamW (PyTorch built-ins) and Lion, LAMB, Shampoo (custom implementations)

**What was built:**
- `optimizers/lion.py` — Lion (Chen et al. 2023): `c = sign(β₁·m + (1-β₁)·g)`, update = `lr·c + weight_decay·θ`, then EMA momentum update; lr=1e-4 default
- `optimizers/lamb.py` — LAMB (You et al. 2019): Adam moments + bias correction + per-layer trust ratio `‖θ‖/‖u‖` clipped at 10; weight_decay=0.01 default
- `optimizers/shampoo.py` — Shampoo (Gupta et al. 2018): Kronecker-factored EMA preconditioners L and R; inverse 4th-roots via eigendecomp every 10 steps; eigendecomp runs on CPU (float32) for MPS compatibility; diagonal Adagrad fallback for params larger than `max_precond_size`
- `optimizers/__init__.py` — exports Lion, LAMB, Shampoo
- `train.py` — `OPTIMIZER_REGISTRY` extended to 11 entries
- `benchmark.py` — `OPTIMIZER_REGISTRY` extended to 10 display entries with colours

**Issues encountered and fixed:**
- Shampoo: `torch.linalg.eigh` not supported on MPS → fixed by moving eigendecomp to CPU
- Shampoo: eigendecomp "failed to converge" with unbounded matrix accumulation → fixed by switching from pure sum (`L += GGᵀ`) to EMA (`L = decay·L + (1-decay)·GGᵀ`), changing epsilon 1e-6 → 1e-4, and wrapping eigendecomp in try/except with identity fallback

**Benchmark run:**
- Ran all 10 optimizers on MNIST and FashionMNIST with MLP, 10 epochs
- Saved comparison figure to `benchmark.png`

---

## Session 7 — README, CHANGELOG, Git, GitHub

**What we discussed:**
- Wanted a record of all changes and a full project explanation
- Wanted the project on GitHub
- Wanted a `requirements.txt`

**What was built / done:**
- `CHANGELOG.md` — 6 rounds documented in reverse-chronological order
- `README.md` — full project documentation: structure, all CLI flags, example commands, dataset table, optimizer table, model descriptions, adding a custom optimizer guide
- `requirements.txt` — `torch>=2.0.0`, `torchvision>=0.15.0`, `matplotlib>=3.7.0`
- `.gitignore` — excludes `__pycache__/`, `data/`, `*.png`, `.DS_Store`, venv directories
- Git initialised, committed, and pushed to `https://github.com/honghaoyu12/OptimizerProject`

---

## Session 8 — Test Suite and CI Pipeline

**What we discussed:**
- Wanted automated tests for every component
- Wanted a GitHub Actions CI pipeline to run them on every push

**What was built:**
- `tests/__init__.py`
- `tests/test_models.py` — 17 tests: MLP (7), ResNet18 (4), ViT (6)
- `tests/test_optimizers.py` — 18 tests: registry completeness, one-step finite-weight check for all 11 optimizers, VanillaSGD/Lion/LAMB/Shampoo-specific behaviour
- `tests/test_metrics.py` — 9 tests: hessian trace (returns float, finite, positive, nan on no-param model), sharpness (returns float, non-negative, finite, weights restored, monotone in epsilon)
- `tests/test_train.py` — 28 tests: DATASET_INFO keys and metadata, build_model across all model×dataset combos, linear_layer_names/weight_norms, train_one_epoch return dict, evaluate, loss decreases over 5 epochs
- `.github/workflows/ci.yml` — GitHub Actions: ubuntu-latest, Python 3.12, CPU-only PyTorch, pip cache, `pytest tests/ -v`

**Results:**
- All 72 tests passed locally in 2.40s
- First CI run on GitHub Actions passed in 48s
- CI badge added to README

---

## Session 9 — Version Control Strategy (this conversation)

**What we discussed:**
- How to safely upgrade the project in the future without breaking the current working state
- Whether git handles this automatically
- Whether a local backup is needed

**Key points covered:**
- Every git commit is a permanent snapshot — you can always restore any previous state
- **Branches** are the right tool for significant upgrades: work on a branch, keep `main` stable
- **Tags** (`git tag v1.0-stable`) are useful named restore points before big changes
- GitHub is already an off-site backup; no separate local backup needed
- The CI pipeline automatically runs tests on every push — regressions are caught before merging
- Recommended workflow: branch → develop → run tests → merge → tag milestone

---

## Project State at End of Session 9

| Component | Status |
|---|---|
| Models | MLP, ResNet-18, ViT |
| Datasets | MNIST, FashionMNIST, CIFAR-10, Tiny ImageNet |
| Optimizers | 11 total (4 PyTorch built-ins + 4 additional built-ins + VanillaSGD + Lion + LAMB + Shampoo) |
| Tests | 72 passing |
| CI | GitHub Actions, green |
| GitHub | https://github.com/honghaoyu12/OptimizerProject |

---

## Session 10 — Housekeeping and Branch Setup

**What we discussed:**
- How to safely upgrade the project in the future without breaking working code
- Whether git automatically handles version history (yes — every commit is a permanent snapshot)
- Whether a local backup is needed (no — GitHub serves as off-site backup; tags useful for named restore points)
- How memory files work: `MEMORY.md` is loaded into context at the start of every new conversation so Claude doesn't start from scratch

**What was done:**
- Updated `MEMORY.md` to reflect the full current project state (all models, datasets, optimizers, test files, CI, known issues, git remote)
- Added `SESSION_LOG.md` to the project and committed it to GitHub
- Added session log summary table and `SESSION_LOG.md` reference to `README.md`
- Created and pushed `new_feature` branch — all future work happens here until ready to merge into `main`

---

---

## Session 11 — CIFAR-100 Dataset

**What we discussed:**
- Adding CIFAR-100 as a fifth dataset (same image size as CIFAR-10 but 100 classes)

**What was done:**
- `train.py` — added `"cifar100"` to `DATASET_INFO` (32×32 RGB, 100 classes, input_size=3072); added normalization stats; `get_dataloaders()` handles CIFAR-100 via `datasets.CIFAR100` sharing the CIFAR-10 augmentation pipeline; CLI help updated
- `benchmark.py` — `CIFAR-100` added to `DATASET_REGISTRY`
- `tests/test_train.py` — `"cifar100"` added to all relevant parametrized tests; test count now 76 (up from 72)
- `CHANGELOG.md` — Round 8 entry added

---

---

## Session 12 — Synthetic Datasets

**What we discussed:**
- Adding 5 synthetic datasets designed to stress-test specific optimizer properties
- Whether sklearn contained any of these (yes — `make_classification` and `make_moons` used)

**What was built:**
- `synthetic_datasets.py` (new) — 5 dataset generators + `SYNTHETIC_LOADERS` registry:
  - `illcond`: ill-conditioned Gaussian (κ=1000), 64 features — tests curvature handling
  - `sparse`: 5 informative out of 100 features via `make_classification` — tests coordinate adaptivity
  - `noisy_grad`: 30% random label flips — tests stochastic robustness
  - `manifold`: `make_moons` embedded in 64-D — tests nonconvex landscapes
  - `saddle`: bimodal positive class at ±2 — tests escape from saddle points
- `train.py` — 5 entries added to `DATASET_INFO` with `"tabular": True`; `get_dataloaders()` delegates to `SYNTHETIC_LOADERS`; `build_model()` raises for non-MLP on tabular data; CLI updated
- `benchmark.py` — 5 synthetic datasets added to `DATASET_REGISTRY`; ResNet/ViT skipped gracefully for tabular datasets
- `requirements.txt` — `scikit-learn>=1.3.0` added
- `tests/test_synthetic.py` (new) — 45 tests covering registry, loader shapes, label validity, NaN checks, standardisation, reproducibility, dataset-specific properties
- `tests/test_train.py` — updated for new dataset keys and tabular guard; test count 76 → 140

---

---

## Session 13 — Bug Fix and Training Validation

**What we discussed:**
- Running a full debug and test pass across the project
- Generating training plots using MNIST and FashionMNIST for speed

**Bug found and fixed:**
- `visualizer.py`: `FileNotFoundError` when `--save-plot` used a subdirectory (e.g. `plots/foo.png`) and the directory didn't exist. Fixed in both `Visualizer.close()` and `plot_benchmark()` by calling `os.makedirs(..., exist_ok=True)` before `savefig`.

**Training runs completed (all clean):**
- MNIST / MLP / Adam → 98.0% test acc
- FashionMNIST / MLP / AdamW → 87.8%
- MNIST / ResNet-18 / SGD → 98.6%
- MNIST / MLP / Lion → 96.5%
- FashionMNIST / MLP / Shampoo → 87.8%
- illcond (synthetic) / MLP / Adam → 92.8%

Plots saved to `plots/` (gitignored). All 140 tests passing throughout.

---

---

## Session 14 — Training Logger and Plot Directory Enforcement

**What we discussed:**
- Ensuring all plots always go into a folder (not the project root)
- Adding structured logging of training runs: timestamped session folders, per-run epoch/batch logs, and an overall summary file

**What was built:**
- `logger.py` (new) — `TrainingLogger` class:
  - Creates `logs/<YYYY-MM-DD_HH-MM-SS>/` at session start
  - `log_run(config, history)` writes `<dataset>_<model>_<optimizer>.log` with epoch-wise CSV and batch-wise step losses
  - `close()` writes `run_summary.log` with timing, run count, and final results table
- `train.py` — default `--save-plot` changed to `plots/training_curves.png`; `--log-dir` flag added; `main()` collects history and calls `TrainingLogger`
- `benchmark.py` — default `--save-plot` changed to `plots/benchmark.png`; `--log-dir` flag added; `run_benchmark()` accepts optional logger; `main()` wires it all together

All 140 tests still passing.

---

---

## Session 15 — Debug and Test Pass

**What we discussed:**
- Running a full debug-and-test pass after the logger and plot enforcement changes from Session 14

**Training runs completed (all clean):**
- MNIST / MLP / Adam → 97.97% test acc
- FashionMNIST / MLP / AdamW → 88.23%
- FashionMNIST / MLP / Lion → 85.90%
- MNIST / MLP / Shampoo → 97.96%
- MNIST / ResNet-18 / SGD → 98.72%

**Verified:**
- All plots saved to `plots/training_curves.png` (no stray files in project root)
- Each run creates `logs/<YYYY-MM-DD_HH-MM-SS>/` with `run_summary.log` + per-run `.log` containing epoch-wise CSV and batch-wise step losses
- All 140 tests continue to pass

---

## Current State After Session 15

| Component | Status |
|---|---|
| Models | MLP, ResNet-18, ViT |
| Datasets | MNIST, FashionMNIST, CIFAR-10, CIFAR-100, Tiny ImageNet + 5 synthetic (illcond, sparse, noisy_grad, manifold, saddle) |
| Optimizers | 11 total |
| Tests | 140 passing |
| CI | GitHub Actions, green on `main` |
| GitHub | https://github.com/honghaoyu12/OptimizerProject |
| Known bugs | None |

---

## Session 16 — Muon, Adan, and AdaHessian Optimizers

**What we discussed:**
- Adding three new optimizers: Muon (orthogonalised Nesterov), Adan (adaptive Nesterov momentum), and AdaHessian (second-order Hessian diagonal preconditioner)

**What was built:**
- `optimizers/muon.py` — Muon: Nesterov momentum with Gram-Schmidt orthogonalisation via `torch.linalg.svd`; 1-D params fall back to SGD; default lr=0.02
- `optimizers/adan.py` — Adan: three EMA terms (gradient, gradient difference, squared gradient difference) for Nesterov look-ahead + element-wise preconditioning; default lr=1e-3
- `optimizers/adahessian.py` — AdaHessian: Hutchinson Hessian diagonal estimator; `requires_create_graph = True` class attribute; default lr=0.1
- `optimizers/__init__.py` — exports Muon, Adan, AdaHessian
- `train.py` — OPTIMIZER_REGISTRY extended to 14 entries; `train_one_epoch()` detects `requires_create_graph` and switches to `autograd.grad(create_graph=True)` path
- `benchmark.py` — OPTIMIZER_REGISTRY extended to 13 entries (Muon magenta, Adan olive, AdaHessian gold)
- `tests/test_optimizers.py` — 19 new tests; total 37 (up from 18)

**Issues encountered and fixed:**
- AdaHessian needs `create_graph=True` during backward, which standard `.backward()` doesn't support cleanly. Fixed via `requires_create_graph` flag checked in `train_one_epoch()`.

---

## Session 17 — Schedulers, Early Stopping, Gradient Clipping, Checkpoints, and Log-Replay Plotting

**What we discussed:**
- Adding LR scheduling options (cosine, step, warmup+cosine)
- Adding early stopping to prevent overfitting
- Adding gradient norm clipping for training stability
- Adding `--weight-decay`, `--seed`, `--checkpoint-dir` flags
- Saving `best.pt` and `final.pt` checkpoints during training
- Plotting training curves directly from saved log files

**What was built:**
- `train.py`:
  - `SCHEDULER_REGISTRY` — `none`, `cosine`, `step`, `warmup_cosine`
  - `EarlyStopping` class — patience-based; saves and restores best-epoch weights
  - `train_one_epoch()` — `max_grad_norm` kwarg; returns `grad_norm_before_clip`
  - `run_training()` — `scheduler`, `patience`, `min_delta`, `max_grad_norm` args; history gains `learning_rates`, `early_stopped_epoch`, `grad_norm_before_clip`
  - New CLI flags: `--scheduler`, `--warmup-epochs`, `--patience`, `--min-delta`, `--max-grad-norm`, `--weight-decay`, `--seed`, `--checkpoint-dir`
  - `Visualizer.update()` — accepts `learning_rate` kwarg; LR trace overlaid on Loss vs Epoch panel
- `benchmark.py` — matching new CLI flags; `run_benchmark()` accepts all new args; `plot_benchmark()` gains LR vs Epoch column
- `tests/test_train.py` — added `TestSchedulers`, `TestEarlyStopping`, `TestGradientClipping`, `TestSeed`; total 68 tests
- `tests/test_checkpoints.py` (new) — 5 tests for checkpoint save and restore
- `tests/test_plot_from_logs.py` (new) — 9 tests for log-replay plotting

Total tests: 227 (up from 190). CI green on `main`.

---

## Session 18 — LR Range Test

**What we discussed:**
- Adding a Learning Rate Range Test (Leslie Smith, 2018) to give users a principled starting LR for any optimizer/dataset pair
- Keeping the implementation self-contained so it can be used independently of `train.py`

**What was built:**
- `lr_finder.py` (new) — `LRFinder` class:
  - Ramps LR exponentially from `start_lr` to `end_lr` over `num_iter` mini-batch steps
  - EMA-smoothed loss tracking; early exit on divergence (`diverge_th * best_loss`)
  - Model and optimizer state unconditionally restored via `finally` block
  - `requires_create_graph` path for AdaHessian compatibility
  - `suggestion()` — LR at steepest negative loss gradient
  - `plot(save_path)` — log-scale figure with suggested LR marked
- `train.py` — `from lr_finder import LRFinder` import; `--find-lr`, `--find-lr-iters`, `--find-lr-plot` CLI flags; pre-training block runs the test and prints the suggestion
- `tests/test_lr_finder.py` (new) — 7 tests: history keys, length, monotone LR, state restoration (weights + LR), suggestion range, AdaHessian compatibility

Total tests: 234 (up from 227). CI green on `main`.

---

## Session 19 — Per-Parameter Group Weight Decay

**What we discussed:**
- `build_optimizer()` was applying weight decay uniformly to all parameters, including biases and normalization-layer parameters where L2 regularization is harmful
- The standard fix: decay only `ndim >= 2` parameters (weight matrices, conv filters); exclude `ndim < 2` parameters (biases, LayerNorm/BatchNorm weights and biases)

**What was built:**
- `train.py`:
  - `make_param_groups(model, weight_decay)` — new helper; splits trainable params into decay (`ndim >= 2`) and no-decay (`ndim < 2`) groups
  - `build_optimizer()` — signature updated: accepts `nn.Module` instead of a parameter iterator; uses `make_param_groups()` when `weight_decay > 0`, falls back to `model.parameters()` otherwise
- `tests/test_train.py` — all existing call sites updated; `make_param_groups` added to imports; 5 new tests in `TestWeightDecay`
- `tests/test_optimizers.py` — updated the one `build_optimizer(name, model.parameters(), ...)` call

Total tests: 239 (up from 234). CI green on `main`.

---

## Session 20 — LR Sweep in benchmark.py

**What we discussed:**
- `benchmark.py` had `--lr` (single value override) but couldn't sweep multiple LRs
- Needed parity with `--weight-decays` which already supports sweeping
- Combined LR + WD sweeps should produce series names like `"Adam (lr=0.001, wd=1e-4)"`

**What was built:**
- `benchmark.py` — `--lr` renamed to `--lrs` (nargs="+"); single value = global override (no suffix, backward-compatible); multiple values = LR sweep (adds `lr=<val>` suffix); `run_benchmark()` inner loop restructured to iterate over `lr_list`; param groups now use `make_param_groups()` when `wd > 0` (matching `train.py` pattern); series colors use `tab20` cmap when sweeping
- `tests/test_benchmark.py` (new) — 6 tests: per-optimizer defaults, single override, two-value sweep, combined LR+WD suffix, WD-only sweep

Total tests: 245 (up from 239). CI green on `main`.

---

## Session 21 — AdaBelief, SignSGD, and AdaFactor

**What we discussed:**
- Adding three optimizers that cover different design strategies: belief-adjusted adaptivity, sign-based updates, and memory-efficient factored second moments

**What was built:**
- `optimizers/adabelief.py` — AdaBelief (Zhang et al., 2020): belief EMA `s = β₂·s + (1-β₂)·(g-m)² + ε` adapts step size by gradient surprise; default lr=1e-3
- `optimizers/signsgd.py` — SignSGD (Bernstein et al., 2018): pure sign updates `±lr`; optional Signum momentum buffer; default lr=1e-2
- `optimizers/adafactor.py` — AdaFactor (Shazeer & Stern, 2018): factored row/column second moment marginals for `O(m+n)` memory; annealing `β₂` via `_rho()`; default lr=1e-3
- `optimizers/__init__.py` — exports all three
- `train.py` — OPTIMIZER_REGISTRY extended with `adabelief`, `signsgd`, `adafactor`
- `benchmark.py` — OPTIMIZER_REGISTRY extended (AdaBelief grey, SignSGD light blue, AdaFactor light orange)
- `tests/test_optimizers.py` — TestAdaBelief (4 tests), TestSignSGD (4 tests), TestAdaFactor (5 tests) added

Total tests: 258 (up from 245). CI green on `main`.

---

## Session 22 — Sophia, Prodigy, and Schedule-Free AdamW

**What we discussed:**
- Sophia: second-order optimizer with clipped Hessian diagonal, a complement to AdaHessian
- Prodigy: removes the need to tune LR by estimating the step scale automatically
- Schedule-Free AdamW: eliminates LR schedules by averaging iterates

**What was built:**
- `optimizers/sophia.py` — Sophia (Liu et al., 2023): HVP every `update_freq=10` steps; `requires_create_graph = True`; Hessian initialized to ones; falls back to `g²` without `create_graph`; update clipped to `[-ρ, ρ]` relative to `h`; default lr=1e-4
- `optimizers/prodigy.py` — Prodigy (Mishchenko & Defazio, 2023): `d` and `A` stored in `param_groups` (survive `state_dict`); per-param `x0`, `s`, `exp_avg`, `exp_avg_sq`; two-pass step (update d then apply Adam with `eff_lr = d * lr`); default lr=1.0
- `optimizers/schedule_free.py` — ScheduleFreeAdamW (Defazio et al., NeurIPS 2024): params = `y = (1-β₁)x + β₁z`; `x` stored in state; `z` reconstructed each step; `get_averaged_params()` returns `x` tensors; default lr=1e-3
- `optimizers/__init__.py` — exports all three
- `train.py` — OPTIMIZER_REGISTRY extended with `sophia`, `prodigy`, `sf_adamw` (20 total)
- `benchmark.py` — OPTIMIZER_REGISTRY extended (Sophia purple, Prodigy crimson, SF-AdamW green; 19 total)
- `tests/test_optimizers.py` — TestSophia (4 tests), TestProdigy (4 tests), TestScheduleFreeAdamW (4 tests) added

Total tests: 276 (up from 258). CI green on `main`.

---

## Session 23 — Benchmark Report Generator

**What we discussed:**
- After a benchmark run, users had to inspect raw CSVs or the comparison plot to understand results — no human-readable narrative existed
- Decided to add a Markdown report generator as a standalone module callable from `benchmark.py`

**What was built:**
- `report.py` (new) — `generate_report(results, config, save_path)`:
  - Section 1: header with generation timestamp
  - Section 2: setup table (datasets, models, optimizers, epochs, batch size, scheduler, LRs, weight decays, seed)
  - Section 3: results overview — one sub-table per `(dataset, model)` combo, columns: final/best test acc, epochs run, time, train-test gap; sorted by final accuracy
  - Section 4: rankings per combo — 🥇 best final accuracy, 🚀 fastest, 📈 best peak accuracy, 🎯 most stable
  - Section 5: per-optimizer summary — bullet per combo with ⚠️ gap warning and early-stop annotation
  - Section 6: key observations — best overall accuracy, fastest/most-stable overall, early-stop and high-gap counts
  - Returns the Markdown string always; writes file only when `save_path != ''`
- `benchmark.py` — `--report-path` flag added (default: `reports/benchmark_report.md`); `generate_report()` called after `plot_benchmark()` in `main()`
- `tests/test_report.py` (new) — 10 tests; all pass in 0.01 s

**Decision: not adding report generation to `train.py`**
- Single-run reports would have no Rankings or Key Observations to populate — the format was designed around multi-optimizer comparison
- `train.py` is already well-served by `logger.py` (per-epoch CSVs, run summary)
- Can revisit if multi-seed averaging or ablation sweeps are added to `train.py`

Total tests: 286 (up from 276). CI green on `main`.

---

## Session 24 — Multi-Seed Averaging

**What we discussed:**
- A single benchmark run is statistically noisy (±1% from weight initialisation alone)
- Wanted the ability to run each combination N times with different seeds, aggregate into mean ± std, and surface the uncertainty everywhere

**What was built:**
- `benchmark.py`:
  - `_aggregate_histories(histories)` — new helper; stacks N seed histories into numpy arrays; computes mean and std for all list-valued keys; handles scalars, `early_stopped_epoch`, `step_losses`, and dict-valued `weight_norms`/`grad_norms`; copies remaining keys from `histories[0]`
  - `run_benchmark()` — new `num_seeds=1` parameter; seed loop rebuilds model + optimizer fresh each iteration; `set_seed(base_seed + seed_idx)` called when `num_seeds > 1` or `seed is not None`; raw history returned as-is when `num_seeds == 1` (no `_std` keys added)
  - `--num-seeds` CLI flag (default: 1)
  - `main()` — removed top-level `set_seed()` (moved into seed loop); passes `num_seeds`; adds it to `report_cfg`; prints banner when `num_seeds > 1`
- `visualizer.py` — `plot_benchmark()` draws `fill_between` error bands (alpha=0.15) after each line when `f"{key}_std"` is present in the history
- `report.py` — Seeds row in Setup table; `"XX.XX ± YY.YY"` formatting in Results Overview and Per-Optimizer Summary when `test_acc_std` present; seed-averaging bullet in Key Observations
- `tests/test_benchmark.py` — 3 new tests (single result per combo, std keys added, no agg-std for num_seeds=1)
- `tests/test_report.py` — 1 new test (± in output when std present)

Total tests: 290 (up from 286). CI green on `main`.

---

## Session 25 — Convergence Speed in Report and Plot

**What we discussed:**
- After adding `--num-seeds`, the report still only showed final/best accuracy and total time
- `target_accuracy_epoch` and `target_accuracy_time` were already being computed by `run_training()` but not surfaced anywhere visible
- Wanted a way to ask "which optimizer hits 90% first?" rather than "which finishes highest?"
- Also wanted the configurable threshold (`--target-acc`) since 95% is unreachable on CIFAR-100

**What was built:**
- `benchmark.py`:
  - `--target-acc` CLI flag (default: 0.95) — threshold forwarded through `run_benchmark()` → `run_training()`
  - `run_benchmark()` signature gains `target_acc: float = 0.95`; `main()` adds it to `report_cfg`
- `report.py`:
  - Setup table: new **Target acc** row
  - Results Overview: two new columns — `"Epochs to N%"` and `"Time to N% (s)"`; shows `"X.X"` or `"—"` (em-dash) when not reached
  - Per-Optimizer bullets: appends convergence details when `target_accuracy_epoch` is present
- `visualizer.py`:
  - `plot_benchmark()`: vertical dotted `axvline` marker on the Test Accuracy panel at `target_accuracy_epoch` (same color as series, `linestyle=":"`, `alpha=0.7`)
- `tests/test_benchmark.py`: 2 new tests (target_acc=0.0 populates epoch; target_acc=1.0 gives None)
- `tests/test_report.py`: 2 new tests (convergence columns present; em-dash when None)

Total tests: 294 (up from 290). CI green on `main`.

---

## Session 26 — LR Sensitivity Plot

**What we discussed:**
- The existing `--lrs` sweep produced a time-series comparison (accuracy over epochs per LR) but didn't answer "how forgiving is this optimizer to LR choice?"
- Wanted a dedicated summary plot: final test accuracy vs learning rate on a log scale, one curve per optimizer
- Key insight: adaptive methods (Adam, AdaBelief) should show a wide flat peak; momentum-only methods (SGD, Muon) should show a sharp spike — seeing this difference visually is more useful than any table

**What was built:**
- `visualizer.py` — new `plot_lr_sensitivity(results, save_path)`:
  - One subplot per `(dataset × model)` combo; one line per base optimizer name
  - Log-scale X axis; `fill_between` error bands when `test_acc_std` present (`--num-seeds` runs)
  - Extracts base optimizer name by splitting series name on ` (` — handles all suffix formats
  - Skips gracefully (print + return) if no `config_lr` found in results
- `benchmark.py`:
  - `config_lr` stored in every aggregated history dict after the seed loop
  - `--save-lr-plot plots/lr_sensitivity.png` flag
  - `main()` calls `plot_lr_sensitivity()` automatically when `--lrs` has ≥2 values
- `tests/test_visualizer.py` (new): 5 tests covering runs, file saving, skip behaviour, multi-optimizer, and std bands

Total tests: 299 (up from 294). CI green on `main`.

---

## Session 27 — Mixed Precision Training (`--amp`)

**What we discussed:**
- Training on CIFAR-100 / Tiny ImageNet is slow on CUDA/MPS; halving memory and getting ~30% speedup with one flag is practical
- Key caveats to handle upfront: GradScaler is CUDA-only; MPS uses autocast without scaling; Sophia and AdaHessian call `backward(create_graph=True)` internally which is incompatible with GradScaler
- Decision: auto-disable AMP for incompatible optimizers with a clear message naming the optimizer and the exact reason — don't silently corrupt results

**What was built:**
- `train.py`:
  - `_AMP_INCOMPATIBLE = (Sophia, AdaHessian)` — module-level constant
  - `train_one_epoch`: `amp` + `scaler` params; forward+loss in `torch.autocast`; `scaler.unscale_()` before gradient norm reads to preserve accuracy; three backward paths (create_graph / scaler / plain)
  - `run_training`: `amp=False` param; AMP setup block (CUDA → autocast+GradScaler; MPS → autocast only; CPU → disabled; incompatible optimizer → disabled with message)
  - `--amp` CLI flag; per-device banner in `main()`
- `benchmark.py`: `amp` param in `run_benchmark`; `--amp` flag; startup banner
- `tests/test_train.py`: 4 new tests (TestAMP) — disabled default, CPU no-op, Sophia auto-disable, AdaHessian auto-disable

**Caveats fully documented in README:**
- Sophia/AdaHessian auto-disabled (create_graph incompatibility explained)
- Gradient norms always in full precision (scaler.unscale_ before reads)
- eval() runs in float32 intentionally
- GradScaler step-skipping on overflow is normal AMP behaviour

Total tests: 303 (up from 299). CI green on `main`.

---

## Session 29 — Per-Layer Gradient Flow Heatmap

**What we discussed:**
- `history["grad_norms"]` already existed with per-layer per-epoch data; just needed a visualisation
- Heatmap (imshow) chosen over line plots: shows all layers × epochs in a single glance, immediately reveals vanishing/exploding patterns
- Implemented as a standalone `plot_grad_flow_heatmap()` to avoid widening the already-5-column benchmark grid
- Zero gradient values clamped to log₁₀ = −6 to avoid −∞ in the colour scale

**What was built:**
- `visualizer.py`: `plot_grad_flow_heatmap(results, save_path)` — one subplot per (dataset, model, series); x=epoch, y=layer (input at bottom), colour=log₁₀|grad|; viridis colourmap; colourbar; skips runs with no grad_norms
- `benchmark.py`: `--save-grad-heatmap` flag (default `plots/grad_flow.png`); import updated; called unconditionally after benchmark run
- `tests/test_visualizer.py`: 6 new tests (TestGradFlowHeatmap) covering normal use, file creation, skip-on-missing-data, multi-optimizer, multi-layer, zero-value handling

Total tests: 314 (up from 308). CI green on `main`.

---

## Session 28 — `torch.compile` and Resume from Checkpoint

**What we discussed:**
- `torch.compile` provides ~20–40% free speedup via kernel fusion; worth adding as an opt-in flag
- Sophia and AdaHessian are incompatible with `torch.compile` (same `create_graph=True` reason as AMP)
- Resume from checkpoint is essential for long runs — allows continuing after interruption without losing progress
- Decision: per-optimizer incompatibility check with an explanatory message (not silent); try/except fallback

**What was built:**
- `train.py`:
  - `_COMPILE_INCOMPATIBLE = (Sophia, AdaHessian)` — module-level constant
  - `--compile` CLI flag; `main()` applies `torch.compile(model)` or prints named incompatibility message; try/except fallback to eager
  - `run_training`: `resume_from: str | None = None` param; loads checkpoint at start of training (`weights_only=False` for PyTorch 2.x); epoch loop changed to `range(start_epoch, epochs+1)`
  - `--resume PATH` CLI flag; same logic in `main()`'s own epoch loop; exits early if checkpoint epoch ≥ `--epochs`
- `benchmark.py`: `compile_model=False` param in `run_benchmark`; per-optimizer incompatibility check via `_COMPILE_INCOMPATIBLE_NAMES = {"sophia", "adahessian"}`; compile inside seed loop with try/except; `--compile` flag; startup banner; `compile_model=args.compile` wired into `main()` call
- `tests/test_train.py`: 5 new tests — `TestCompile` (3: compiled model trains, sentinel membership, Sophia warning text) + `TestResume` (2: epoch count after resume, no-crash on zero-weight checkpoint)

Total tests: 308 (up from 303). CI green on `main`.

---

## Current State

| Component | Status |
|---|---|
| Models | MLP, ResNet-18, ViT |
| Datasets | MNIST, FashionMNIST, CIFAR-10, CIFAR-100, Tiny ImageNet + 5 synthetic |
| Optimizers | 20 in `train.py` (adam, adamw, nadam, radam, adagrad, sgd, rmsprop, vanilla_sgd, lion, lamb, shampoo, muon, adan, adahessian, adabelief, signsgd, adafactor, sophia, prodigy, sf_adamw); 19 in `benchmark.py` |
| Schedulers | none, cosine, step, warmup_cosine |
| Early stopping | patience-based, restores best-epoch weights |
| Gradient clipping | global norm clipping via `--max-grad-norm` |
| Weight decay | per-parameter-group via `make_param_groups()` — biases and norm params excluded |
| LR range test | `lr_finder.py` + `--find-lr` in `train.py` |
| LR sweep | `--lrs` in `benchmark.py` — single value = override, multiple = sweep with series labels |
| Multi-seed averaging | `--num-seeds` in `benchmark.py` — mean ± std histories; error bands in plot; ± in report |
| Convergence speed | `--target-acc` in `benchmark.py` — "Epochs to N%" / "Time to N%" columns in report; axvline marker in plot |
| LR sensitivity plot | `plot_lr_sensitivity()` in `visualizer.py` — acc vs log-LR, auto-generated when `--lrs` has ≥2 values |
| Mixed precision | `--amp` in both CLIs — float16 autocast+GradScaler on CUDA; autocast only on MPS; auto-disabled for Sophia/AdaHessian |
| torch.compile | `--compile` in both CLIs — static graph tracing speedup; auto-disabled for Sophia/AdaHessian; try/except fallback |
| Resume from checkpoint | `--resume PATH` in `train.py`; `resume_from=PATH` in `run_training()` — restores model+optimizer state |
| Gradient flow heatmap | `plot_grad_flow_heatmap()` in `visualizer.py`; `--save-grad-heatmap` in `benchmark.py`; x=epoch, y=layer, colour=log₁₀\|grad\| |
| Logging | `logger.py` — timestamped session folders, epoch/batch CSVs, summary |
| Benchmark reporting | `report.py` — Markdown narrative report via `--report-path` in `benchmark.py` |
| Tests | 314 passing |
| CI | GitHub Actions, green on `main` |
| GitHub | https://github.com/honghaoyu12/OptimizerProject |
| Known bugs | None |

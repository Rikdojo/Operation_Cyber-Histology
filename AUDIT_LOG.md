# Incident Audit Log

This log documents the main defects discovered in the recovered Operation Cyber-Histology codebase and the commits that introduced the corresponding fixes in the repository history.

## Scope

Audited files:

- `Code/config.json`
- `Code/data.py`
- `Code/models.py`
- `Code/train.py`
- `Code/trainer.py`
- `Code/evaluate.py`
- `Code/runner.py`
- `Code/transfer.py`
- `Code/utils.py`
- `tests/test_pipeline.py`

## Core Recovered-Code Fixes

| File name | Problem manifestation | Root cause | Correction implemented | Git commit hash |
|---|---|---|---|---|
| `Code/config.json` | Pipeline could not be controlled externally and required code edits for different datasets/models. | Dataset name, model name, channel count, class count, learning rate, batch size, and epoch settings were not centralized. | Added a JSON configuration file and routed training through configuration values. | `6307acb` |
| `Code/config.json` | Only one dataset shape could be represented safely. | Dataset-specific metadata was stored as flat global fields instead of a dataset registry. | Added a `DATASETS` mapping for `cells`, `chest`, `lesions`, and `orgs`, each with channels and class counts. | `79c80f6` |
| `Code/config.json` | The restored training setup used an extreme dropout value. | `DROP_RATE` was recovered as `0.99`, which would randomly disable almost all classifier activations and severely underfit. | Replaced the value with a configurable `DROP_RATE` default of `0.5`. | `0e80007` |
| `Code/data.py` | Data loading failed when dataset files used the restored assignment naming convention. | Loader expected a hardcoded alternate file suffix instead of `{dataset}.pt`. | Standardized file lookup to `{dataset}.pt`. | `24fbfee` |
| `Code/data.py` | Validation metrics were unreliable because validation samples could also be included in training. | The training split used the full recovered training tensor before slicing out validation data. | Split `train_images` and `train_labels` so validation samples are excluded from the training dataset. | `6307acb` |
| `Code/data.py` | Validation data could be biased by a fixed, ordered split. | The validation subset was taken from a deterministic final slice of the recovered training tensor, so tensor order could affect the split. | Replaced the fixed slice with a seeded random permutation to create randomized, disjoint train/validation indices. | `a08bd60` |
| `Code/data.py` | Validation and test performance could be inflated by preprocessing leakage. | Normalization statistics were not restricted to the training split. | Computed mean and standard deviation from training data only, then reused them for train, validation, and test tensors. | `6307acb` |
| `Code/data.py` | Color datasets were normalized with unsuitable global statistics. | Channel statistics were collapsed together instead of being computed per image channel. | Implemented training-only per-channel mean/std normalization for train, validation, and test tensors. | `a08bd60` |
| `Code/trainer.py` | `CrossEntropyLoss` could fail or train on incorrectly shaped targets. | Labels were stored as `(N, 1)` tensors and not consistently converted to one-dimensional integer class targets. | Converted labels with `.view(-1).long()` during training and evaluation. | `7535784` |
| `Code/trainer.py` | Gradients could accumulate across mini-batches and destabilize learning. | Optimizer gradients were not cleared before each backward pass. | Called `optimizer.zero_grad()` before computing gradients for each batch. | `6307acb` |
| `Code/trainer.py` | Accuracy calculation was harder to reason about and shadowed a Python built-in. | The variable name `sum` was used for sample counting. | Renamed the counter to `total` and used it consistently in loss/accuracy calculations. | `7535784` |
| `Code/trainer.py` | Final evaluation could use a worse model than an earlier validation epoch. | The training loop did not restore the best validation-loss state after training. | Added best-state tracking, early stopping, and restoration of the best validation model. | `f314b14` |
| `Code/models.py` | ResNet18 produced no logits, causing training/inference to fail. | `forward()` called the classifier but did not return its output. | Returned `self.classifier(out)` from the ResNet18 forward pass. | `6307acb` |
| `Code/models.py` | ResNet18 gradients could be weakened or neutralized by a non-learning activation placeholder. | Default activation was set to identity-like behavior instead of a nonlinear activation. | Set the default activation to `ReLU` and made activation configurable. | `6307acb` |
| `Code/models.py` | VGG blocks could receive incorrect channel dimensions after the first convolution in a block. | `current_in_channels` was not advanced after each convolution. | Updated `current_in_channels` inside the VGG block construction loop. | `6307acb` |
| `Code/models.py` | VGG configuration C tail convolutions had incorrect spatial behavior. | The 1x1 convolution tail used the same padding as 3x3 convolutions. | Used zero padding for 1x1 convolutions and normal padding for 3x3 convolutions. | `6307acb` |
| `Code/models.py` | AlexNet failed for grayscale datasets and datasets with class counts other than 11. | Input channels and output classes were hardcoded. | Changed AlexNet to accept `in_channels` and `num_classes` from the configuration. | `6307acb` |
| `Code/models.py` | AlexNet classifier shape was incompatible with the feature tensor for 64x64 inputs. | The first linear layer expected 2048 features while the adapted feature extractor produced 3072. | Set the first AlexNet classifier layer to `nn.Linear(3072, 1024)`. | `6307acb` |
| `Code/models.py` | Task 2 lightweight variants could not run from the recovered stubs. | Lightweight classes were missing valid model definitions. | Implemented lightweight AlexNet, VGG16, and ResNet18 variants with reduced parameter counts and the same input/output contract. | `e938a98` |
| `Code/train.py` | Only a single hardcoded experiment could be run cleanly. | Training entry point did not expose dataset/model/task selection. | Added task-aware run-list support for configured dataset/model combinations. | `b3baeb2` |
| `Code/train.py` | Running `python3 Code/train.py --task ...` could crash before training started. | The parser only defined `--task`, but `main()` still tried to read removed arguments. | Loaded `Code/config.json` directly and kept `--task` as the supported command-line switch. | `180f2b1` |
| `Code/train.py` | `RUN_ALL=false` still behaved like a multi-model run. | The single-run branch returned every configured model instead of the selected `DATA` and `MODEL`. | Made task 1 return one configured dataset/model pair and task 2 return one baseline debug run when `RUN_ALL` is false. | `180f2b1` |

## Supporting Changes

### Execution and Evaluation Infrastructure

| File name | Problem manifestation | Root cause | Correction implemented | Git commit hash |
|---|---|---|---|---|
| `Code/runner.py` | Task 1, Task 2, and Task 3 needed consistent experiment execution. | Training, evaluation, checkpointing, and metric collection were split across ad hoc entry points. | Added a shared runner that builds loaders, trains models, evaluates test metrics, saves checkpoints, and returns one result row per experiment. | `fc5bce9` |
| `Code/runner.py` | Relative data paths pointed at `Code/data` instead of the repository-level `data` folder. | `get_data_path()` resolved paths from the `Code/` directory. | Resolved relative data paths from the project root with `Path(__file__).resolve().parent.parent`. | `4582999` |
| `Code/runner.py` | Green benchmarking could not report useful local device behavior on Apple Silicon. | Device selection only considered CUDA and CPU, and memory reporting only used CUDA peak-memory APIs. | Added CUDA/MPS/CPU device selection, MPS memory reporting, and an explicit CPU fallback value. | `1fb8472` |
| `Code/evaluate.py` | GPU inference failed when the model was on GPU but test images stayed on CPU. | Inference moved neither input images nor predictions consistently across devices. | Moved images to the selected device before forward pass and moved labels/predictions back to CPU for metric calculation. | `4ac2bf0` |
| `Code/evaluate.py` | Macro metrics could break on classes with no predicted samples. | Classification metrics did not guard against undefined precision/recall cases. | Used `zero_division=0` for macro precision, recall, and F1 calculation. | `4ac2bf0` |
| `Code/transfer.py` | Task 3 could not compare scratch training, frozen feature extraction, and fine-tuning. | The recovered project had no transfer-learning setup for the scarce `organs` target. | Added model construction for `scratch`, `feature_extraction`, and `fine_tune` modes using the `orgs` source checkpoint. | `fc5bce9` |
| `Code/config.json` | Task 3 had no central settings for target data, source checkpoint, model, transfer modes, or augmentation. | The scarce-data transfer experiment required settings outside the normal dataset/model matrix. | Added the `task3` configuration block for `orgs` to `organs` transfer with checkpoint and mode settings. | `5f4255e` |

### Additional Log, Runner, and History Updates

| File name | Problem manifestation | Root cause | Correction implemented | Git commit hash |
|---|---|---|---|---|
| `Code/train.py` | Task 2 benchmark CSV did not clearly separate baseline and light runs. | Model names were changed during execution, but the output row did not preserve an explicit run mode. | Added `mode`, total/trainable parameter counts, runtime, latency, and memory fields to the CSV row. | `1fb8472` |
| `Code/utils.py` | Results output could fail if the target folder did not exist. | CSV writing assumed the parent output directory was already present. | Created the output directory before writing metrics. | `2de48be` |
| `Code/runner.py` / `Code/utils.py` | Training produced no reusable loss-history artifacts. | The pipeline printed epoch logs but did not save training/validation loss curves. | Saved loss-curve PNG files under `results/history/` for each run. | `f314b14` |
| `Code/runner.py` | Model artifacts were not organized consistently across tasks. | Checkpoint paths were not connected to the shared output directory. | Saved model checkpoints under `results/model/` with dataset/model/mode-specific filenames. | `f314b14` |
| `Code/data.py` | Data augmentation for Task 3 introduced an avoidable dependency. | A small optional transform used `torchvision` even though the project only needed a simple training-time flip. | Replaced it with a PyTorch-only horizontal flip augmentation. | `1fb8472` |
| `tests/test_pipeline.py` | The integration branch needed a committed testing framework. | The recovered project did not include tests for config, model shapes, loaders, runner helpers, or device fallback behavior. | Added `unittest` coverage for config sections, run lists, model shapes, synthetic `.pt` data loading, green metric fields, and CPU memory fallback. | `6163c34` |
| `README.md` / `REPORT.md` | Final reproduction instructions and benchmark interpretation were incomplete. | Documentation lagged behind the unified Task 1-3 pipeline and final benchmark outputs. | Documented task commands, output files, green metrics, transfer workflow, and final benchmark recommendations. | `2206831` |

## Current Open Risks

| Area | Risk | Recommendation |
|---|---|---|
| Dependency reproducibility | Dependencies are documented in `README.md`, but there is no committed `requirements.txt`. | Add a small dependency file before final packaging if the submission expects installable dependencies as a file. |
| Statistical robustness | The final benchmarks are single-seed runs. | If time permits, rerun the important recommendations with additional seeds and report mean/std values. |
| Result artifact packaging | The repository ignores newly generated `results/` files and all local `data/` files by default. | Keep the required CSV/checkpoint artifacts tracked or submit any additional generated evidence separately if the course requires it. |
| Shuffle reproducibility | The train/validation split is seeded, but `DataLoader(..., shuffle=True)` does not currently pass a seeded generator. | Add a seeded `torch.Generator` to the training loader if strict run-to-run shuffle reproducibility is required. |

## Verification Evidence

Local checks performed on the current `integration` worktree:

```bash
python3 -m py_compile Code/train.py Code/trainer.py Code/data.py Code/models.py Code/evaluate.py Code/runner.py Code/transfer.py Code/utils.py
```

All listed files compiled successfully.

The current testing framework runs with:

```bash
python3 -m unittest discover -s tests
```

The tests cover config loading, task 1/task 2 run lists, model output shapes, synthetic `.pt` data loading, green metric output fields, and device/memory fallback behavior.

Current benchmark artifacts expected locally:

```text
results/task1_test_metrics.csv
results/task2_test_metrics.csv
results/task3_test_metrics.csv
results/model/Light_ResNet18_orgs.pt
```

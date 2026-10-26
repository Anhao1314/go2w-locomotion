# Hierarchical RL turns an impossible long-horizon quadruped task into a reliable one: a controlled comparison

**Design and Implementation of a Quadruped Robot Locomotion Control System Based on Hierarchical Reinforcement Learning** (undergraduate thesis project repository)

[中文版](README.md) · [Docs index](docs/README.md) · [Full Phase-1 research report](docs/PHASE1_REPORT.md) · [Experiment protocol](docs/EXPERIMENT_DESIGN.md) · [Daily journal](docs/journal/)

---

## One-line result

> Under identical task, observation and training budget, an **end-to-end single-layer policy fails completely on a four-stage long-horizon task (0/20, falls in every episode) after 1500 iterations, while a hierarchical architecture converges to 100% (20/20) within 100 iterations**. On an easy task both succeed, with the hierarchical agent converging 3x faster. Failures are attributable: the single-layer policy dies at the walk-to-turn gait switch.

## Key numbers

### L3 (hard): forward 2 m -> turn 90 deg in place -> forward 2 m -> stop 1 s

| Metric | Single layer (12-dim joints) | Layered (2-dim commands -> frozen S0) |
| --- | --- | --- |
| Success rate (frozen 20 episodes) | **0/20** (fell every episode) | **20/20** |
| Convergence iteration | not converged at 1500 | **100** |
| Training wall-clock | 1665 s (no usable policy) | **173 s** (early stop) |
| Failure point | falls 3-5 s into stage 1 (turning) | — |

### L1 (easy): forward 1.2 m -> stop 0.5 s

| Metric | Single layer | Layered |
| --- | --- | --- |
| Success rate | 100% (converged at 150 iters) | 100% (**50 iters**) |

**What the ladder means**: on the easy task the hierarchy is merely *faster* (an efficiency win); once the task requires switching locomotion modes, it becomes *possible vs impossible* — and the single-layer failure is precisely localized to the walk-to-turn switch by stage reach rates, a diagnostic only the layered structure provides.

**Sample videos**: [layered completing all four stages](media/training/robot_motion_l3_layered.mp4) · [single layer falling at the turn](media/training/robot_motion_l3_single_fail.mp4) · [sample-efficiency curves](media/training/sweep_ab_comparison.png)

Full reports: [L3 comparison](reports/training/l3_ab_comparison.md) · [L1 comparison](reports/training/ab_comparison.md) · [M1 low-level policy](reports/locomotion/m1_evaluation.md)

## System

```text
Task/stage manager (rule layer: closed-loop velocity commands + stage gating)
   |  [vx, wz] command
   v
S1 command policy (PPO, 2-dim actions) -- layered group --+
                                                          +-> 12 joints -> Unitree Go2 (Isaac Sim 5.1)
S0 locomotion policy (PPO, frozen, reused) --------------+
   ^
   |  48-dim proprioception (M1-pretrained: vx_rmse 0.057 m/s, three seeds)
```

- **Single-layer group**: the 53-dim observation maps directly to 12-dim joint actions — identical task information to the layered group
- **Layered group**: S1 learns in 2-dim command space; execution is delegated to a pretrained, frozen S0

## Engineering for reproducibility

| Facility | Description |
| --- | --- |
| Pre-registered protocol | evaluation seeds E={0..19}, metrics and thresholds frozen before training ([EXPERIMENT_DESIGN](docs/EXPERIMENT_DESIGN.md)) |
| Per-run evidence bundle | `run_config.json` (git SHA/dependency versions/command line) + SHA-256 manifest of every file, auto-generated |
| Training reports | every run auto-produces a Markdown report with first/last/extrema/trends and automated anomaly detection ([example](reports/training/2026-10-24_01-18-00.md)) |
| Convergence early-stop | deterministic evaluation on 2048 envs every 50 iterations; stops after consecutive passes and records the convergence point |
| Live dashboard | local web panel: progress, reward curves, GPU, snapshot replay, report and video links |
| Motion videos | recorded body trajectories rendered as 3-D skeleton animations (success and failure both replayable) |
| Daily journal | [docs/journal/](docs/journal/): goals, decisions and **failures-with-fixes** per day (a dozen real debugging cases) |

## Honest boundaries

- **Simulation only**: no real-robot experiments; conclusions hold for Isaac Sim 5.1
- **One training seed per group**: cross-seed variance is pending (planned thesis work)
- **S0 pretraining cost**: the layered S0 took ~1200 s to pretrain; even counting it, the layered total (1374 s) is below the single layer (1665 s, and it failed) — but part of the layered advantage comes from action abstraction and S0 reuse rather than S1 learning faster
- **Closed-loop commands encode task knowledge**: the rule layer's heading correction embeds part of the task prior — this is a deliberate hierarchical trade-off, discussed in the report

## Repository layout

| Path | Content |
| --- | --- |
| [`locomotion/`](locomotion/README.md) | Phase-2 code: task environments, A/B trainer, evaluation, action mapping |
| [`mora/`](docs/MORA_TRAIN.md) | Layered runtime system layer (S2->S1->S0 contracts, memory, progress loop) |
| [`cpp/`](cpp/README.md) | C++ control stack (FK/IK/MPC numerically validated) + guardrail kinematics core |
| [`reports/`](reports/training/ab_comparison.md) | Training reports, comparison reports, sweep data (all auto-generated) |
| [`docs/`](docs/README.md) | Protocol, architecture, roadmap, daily journal, ADR decision records |
| `scripts/` | Training, evaluation, sweep, report, dashboard and video entry points |
| `media/training/` | Key videos and curves (process videos archived under `media/archive/`) |

## Phase-1: Go2W wheeled navigation (completed, archived)

This repository previously hosted long-horizon navigation research on the Unitree Go2W
wheeled quadruped (the first MoRA-Train adapter: curve 20/20, multi-segment 20/20,
junction 40/40, C++ S0 numerically validated). The full research report is preserved at
[docs/PHASE1_REPORT.md](docs/PHASE1_REPORT.md); the Phase-2 comparison methodology and
engineering facilities evolved from that stage.

## Reproducing

```powershell
$env:PYTHONPATH = "$PWD"; $env:OMNI_KIT_ACCEPT_EULA = "YES"

# Layered group (L3)
.venv311\Scripts\python.exe scripts\train_ab.py --mode layered `
    --s0-checkpoint <S0 checkpoint> --num_envs 2048 --max_iterations 1500 --seed 0

# Single-layer group (L3)
.venv311\Scripts\python.exe scripts\train_ab.py --mode single `
    --num_envs 2048 --max_iterations 1500 --seed 0

# Frozen-seed evaluation
.venv311\Scripts\python.exe scripts\eval_policy.py --task Go2Loco-Sequence-v0 `
    --run-dir <run> [--layered --s0-checkpoint <S0>] --episodes 20
```

Environment: Python 3.11 + Isaac Lab 2.7.0 + Isaac Sim 5.1.0.0 + RTX 5060 Ti (version pins in [locomotion/README](locomotion/README.md)).

## License and contributions

Original code is [MIT licensed](LICENSE); Go2W assets and third-party materials retain their own licenses ([notices](docs/THIRD_PARTY_NOTICES.md)). Phase-1 contribution credits are preserved in the archived report ([docs/PHASE1_REPORT.en.md](docs/PHASE1_REPORT.en.md)).

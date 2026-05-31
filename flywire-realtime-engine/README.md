> **This repo has merged into the [synaptech-platform monorepo](https://github.com/ShrekDino/synaptech-platform) → `packages/flywire-realtime/`**.
> Issues and PRs should be directed there. This repo remains live for stars and reference.

# FlyWire Realtime Engine

**GPU-accelerated closed-loop simulation of the Drosophila melanogaster whole-brain connectome at 60 Hz.**

[![Python 3.11+](https://img.shields.io/badge/python-3.11+-blue.svg)](https://www.python.org/)
[![PyTorch](https://img.shields.io/badge/PyTorch-2.7+-ee4c2c.svg)](https://pytorch.org/)
[![ROCm](https://img.shields.io/badge/ROCm-6.x-green.svg)](https://rocm.docs.amd.com/)
[![License](https://img.shields.io/badge/license-MIT-green.svg)](LICENSE)
[![GitHub](https://img.shields.io/badge/GitHub-connectome--gpu--runtime-181717.svg)](https://github.com/)

---

## Executive Summary & The Vision

### The Linux of Whole Brain Emulation

The connectome of *Drosophila melanogaster* — the first complete synaptic wiring diagram of an adult brain, mapped at nanoscale resolution by the FlyWire Consortium — represents a watershed moment in neuroscience. For the first time, we possess a structural blueprint of every neuron and every synapse in a biological brain.

**FlyWire Realtime Engine** is an open-source, GPU-accelerated runtime that transforms this static wiring diagram into a **living digital twin** — a closed-loop, real-time simulation of neural population dynamics that can sense, decide, and act in a virtual environment.

Our mission is to build the foundational open-source infrastructure layer for whole-brain emulation:
- **Deterministic**: Every tick produces reproducible dynamics from identical initial conditions.
- **Real-time**: The simulation keeps pace with biological time at 60 Hz — matching the visual system's temporal resolution.
- **Portable**: Architecture-agnostic design runs on NVIDIA CUDA GPUs today, with a strategic migration path to AMD's unified-memory Strix Halo APUs.
- **Extensible**: The neuropil-granular 78-node connectome serves as a reference architecture for future expanded models (single-neuron, spiking neural networks, bio-physical compartment models).

### Digital Continuity Without Personality Drift

Current approaches to digital consciousness suffer from a fundamental flaw: **personality drift** caused by asynchronous, non-real-time inference loops. By anchoring the simulation to a deterministic wall-clock at biological time-scales, FlyWire Realtime Engine establishes the architectural pattern for high-fidelity digital continuity — a substrate where state evolves synchronously with the physical world.

---

## Technical Architecture

### Overview

```
┌─────────────────────────────────────────────────────────┐
│                    FLYWIRE REALTIME ENGINE               │
│                                                          │
│  ┌──────────────┐    ┌──────────────┐   ┌─────────────┐  │
│  │ Sensory      │    │ Connectome   │   │ Motor       │  │
│  │ Injection    │───▶│ GPU Step     │──▶│ Decode      │  │
│  │ (CPU→GPU)    │    │ (all VRAM)   │   │ (GPU→CPU)   │  │
│  └──────────────┘    └──────┬───────┘   └──────┬──────┘  │
│                             │                   │         │
│                             ▼                   ▼         │
│                      ┌──────────────┐   ┌─────────────┐  │
│                      │ Activity     │   │ Body Physics│  │
│                      │ Tensor (GPU) │   │ (CPU)       │  │
│                      └──────────────┘   └──────┬──────┘  │
│                                                 │         │
│  ┌──────────────┐    ┌──────────────┐           │         │
│  │ Visualizer   │◀───│ Motor        │◀──────────┘         │
│  │ Bridge (UDP) │    │ Broadcaster  │                     │
│  └──────┬───────┘    └──────────────┘                     │
│         │                                                 │
│  ┌──────▼───────┐                                         │
│  │ Stimulus     │──── UDP reverse channel (port 5556)     │
│  │ Receiver     │     (mouse click → sensory injection)   │
│  └──────────────┘                                         │
└─────────────────────────────────────────────────────────┘
```

### Core Execution Pipeline

Each tick at 16.67 ms executes a deterministic sequence:

| Phase | Location | Operation | Latency |
|---|---|---|---|
| **Sensory Injection** | CPU | Body state → 78-float `I_eff` vector (proprioception, baseline current, Gaussian noise, mouse-stimulus) | ~5 µs |
| **GPU Brain Step** | VRAM | Sparse COO matrix-vector multiply (78×78, 5,796 NNZ) + sigmoid activation + recurrent dynamics | **~50 µs** |
| **Motor Decode** | GPU→CPU | Gather 12 motor-channel values from 78-neuron activity via index_select + reduce; only 12 scalars cross PCIe | ~10 µs |
| **Body Physics** | CPU | 3-DOF rigid-body dynamics, gait cycle, leg kinematics, path history | ~50 µs |
| **Logging** | CPU | O(1) ring-buffer write (pre-allocated, zero heap allocs on hot path) | ~5 µs |
| **UDP Broadcast** | Background thread | JSON-serialized state → sendto (fire-and-forget, non-blocking) | 0 µs (async) |

**Total: ~120 µs** — using **0.7%** of the 16,667 µs budget.

### Zero-Copy Memory Architecture

```python
# The weight matrix lives in VRAM permanently — never re-loaded.
self.W_T = torch.sparse_coo_tensor(idx, vals, shape, device='cuda')

# The activity vector stays GPU-resident between ticks.
self.activity = a_next  # still on GPU

# Only a 78-float sensory vector (~312 B) crosses host→device per tick.
I = torch.from_numpy(input_vec).float().to(self.device, non_blocking=True)

# Motor decode gathers ~12 scalars from the GPU activity vector.
vals = activity_gpu.index_select(0, idxs)  # GPU gather
val = vals.mean().item()                   # 1 float crosses device→host
```

This architecture ensures:
- **No PCIe bottlenecks**: The 78×78 connectome multiply runs entirely in VRAM — the single hottest operation is a sparse matmul at ~28 µs.
- **Deterministic latency**: No dynamic memory allocation on the hot path. All buffers pre-allocated at construction time.
- **Cache-friendly access**: The 78-element activity vector fits entirely in a single GPU warp (2 warps at 32 threads each).

### Connectome Processing

The raw FlyWire projectome (78×78, float64, 95.3% dense, 5,796 non-zero entries) undergoes a deterministic normalization pipeline before deployment to the GPU:

1. **Diagonal zeroed**: Self-connections excluded from normalization to prevent autapse dominance.
2. **Row-normalised**: Each row divided by its off-diagonal sum (unit total input per source neuropil).
3. **Alpha-scaled**: Multiply by coupling strength `α = 0.6`.
4. **Self-connection restored**: Diagonal set to `δ = 0.15` (leaky integrator time constant).
5. **Transpose**: `W^T` computed for efficient column-wise gather during the recurrent step.

The GPU step computes:

```
activity[t+1] = σ( W^T @ activity[t] + β · I_eff − γ · (activity[t] − b) + ε )
```

Where:
- `W^T` : 78×78 sparse COO weight matrix (VRAM-resident)
- `I_eff` : Sensory injection vector (78 floats, transferred each tick)
- `β = 0.8` : Sensory gain
- `γ = 0.3` : Homeostatic decay toward baseline `b = 0.05`
- `ε ~ Uniform(0, 0.03)` : Intrinsic noise
- `σ` : Logistic sigmoid

### Visualizer Bridge (Asynchronous UDP)

The engine communicates with the Pygame visualizer through a **dual-channel UDP protocol**:

| Channel | Port | Direction | Content | Frequency |
|---|---|---|---|---|
| **Motor Broadcast** | 5555 | Engine → Visualizer | `{pos, heading, turning_rate, walking_speed, ...}` | 60 Hz (every tick) |
| **Stimulus Reverse** | 5556 | Visualizer → Engine | `{tx, ty, active}` | On mouse click/drag |

Both channels are **fire-and-forget**: no TCP handshake, no retransmission, no backpressure. The broadcast uses a background daemon thread with an internal `queue.Queue(maxsize=64)` — the tick loop calls `put_nowait()` in O(1) and never blocks on network I/O.

---

## Hardware Portability Blueprint

### Current Benchmarks (NVIDIA RTX 3060 Laptop GPU)

| Metric | Value |
|---|---|
| GPU | NVIDIA GeForce RTX 3060 Laptop (6 GB VRAM) |
| CUDA Cores | 3,840 |
| PyTorch Version | 2.7.1+cu118 |
| Sparse Matmul Latency | **~28 µs** (single tick) |
| Full Tick Latency | **~1.2 ms** (steady-state, including warmup) |
| Headroom vs 16.67 ms Budget | **92.8%** |
| Max Theoretical Throughput | **~830 ticks/second** |
| Measured Warmup Latency | ~110 ms (10 dummy tensors for JIT compilation) |
| Zero Latency Violations | **✓** (verified over 10,000+ ticks) |

### Strategic Pipeline: AMD Strix Halo APUs

The next-generation target architecture is AMD's **Strix Halo** accelerated processing unit, featuring up to **16 Zen 5 CPU cores** and a **40-COMpute Unit RDNA 3.5 GPU** with **128 GB unified memory** (accessible to both CPU and GPU without PCIe transfers).

**Why Strix Halo eliminates the remaining architectural constraints:**

| Constraint | Current (RTX 3060, discrete) | Strix Halo (unified memory) |
|---|---|---|
| **Sensory injection** | 78 floats × PCIe (312 B/tick) | Zero-copy pointer-sharing between CPU and GPU |
| **Activity logging** | GPU→CPU copy (312 B/tick) | Pointer aliasing — CPU reads directly from GPU memory |
| **Motor decode** | 12 scalars × device→host sync | GPU kernel writes motor values to host-coherent memory |
| **Maximum model size** | 6 GB VRAM (~2×10⁶ neurons) | 128 GB unified (~4×10⁷ neurons) |
| **CPU↔GPU synchronisation** | Implicit CUDA sync on `.item()` | No PCIe round-trip — coherence via Infinity Fabric |

The unified memory model of Strix Halo means the entire sensory-injection → brain-step → motor-decode → logging pipeline can execute **without a single PCIe transfer**. Our zero-copy architecture was designed for exactly this transition — every design decision (non‑blocking sensory transfer, GPU‑resident activity, index‑select motor gather) maps directly to the unified memory paradigm.

### Scaling Roadmap

```
2024 Q4 ─── 78-neuron neuropil model (current)
               │
               ▼
2025 Q1 ─── Single-neuron model (~20,000 neurons)
               │  • Each neuron: 3-compartment passive cable model
               │  • GPU batch: 20,000 × 16 µs = 320 ms → needs sub-batching
               │
               ▼
2025 Q2 ─── Spiking neural network (adaptive LIF, ~100,000 neurons)
               │  • Discrete event queue on GPU
               │  • 5 µs per spike event → 1,000 events/tick budget
               │
               ▼
2025 Q3 ─── Strix Halo deployment (128 GB unified memory)
               │  • Full brain-scale model (~10⁵−10⁶ neurons)
               │  • Zero-copy end-to-end
               │
               ▼
2025 Q4 ─── Biophysical multi-compartment model
               │  • Hodgkin-Huxley dynamics
               │  • Dendritic tree reconstruction from FlyWire morphologies
```

---

## Live Interactive Prototype Demo Guide

### Prerequisites

- **GPU**: NVIDIA GPU with CUDA Compute Capability 7.0+ (tested on RTX 3060)
- **Memory**: 8 GB+ system RAM, 6 GB+ VRAM
- **Conda**: [Miniforge](https://github.com/conda-forge/miniforge) or [Anaconda](https://www.anaconda.com/)

### Installation

```bash
# 1. Clone the repository
git clone https://github.com/<your-org>/flywire-realtime-engine.git
cd flywire-realtime-engine

# 2. Create the conda environment
conda env create -f environment.yml
conda activate flybrain

# 3. Install PyTorch with CUDA support
pip install torch torchvision torchaudio --index-url https://download.pytorch.org/whl/cu118
```

### Launch the Full Interactive Demo

Open **two terminal windows**:

#### Terminal 1 — Virtual Arena Visualizer

```bash
conda activate flybrain
python fly_view.py
```

This opens a Pygame window showing:
- The fly in a 2D top-down view (compound eyes, legs with tripod gait, wings, proboscis)
- Real-time motor bar HUD (walking speed, turning rate, wing amplitude, etc.)
- Investor metrics panel (firing rate, latency, tick count)
- Drawn trail of the last 100 positions

#### Terminal 2 — Connectome Engine

```bash
conda activate flybrain
python flybrain_activity.py --closed-loop --realtime --enable-viz
```

The engine broadcasts 60 Hz state data to the visualizer over UDP port 5555.

### Interaction

| Action | Result |
|---|---|
| **Left-click** in visualizer | Places a food/light stimulus at the cursor. The fly's connectome steers toward it. |
| **Left-click + drag** | Continuously updates the stimulus position — the fly chases the mouse in real time. |
| **Release left-click** | Stimulus remains at the last position; the fly continues toward it. |
| **Press `C`** | Clears the stimulus; the fly returns to straight exploratory walking. |
| **Press `ESC`** | Exits the visualizer. |

### Expected Behavior

When you click and drag the mouse around the virtual arena, the fly will:
1. **Turn hard** toward the stimulus position (~50° heading change in 200 ticks)
2. **Accelerate** to chase (3× speed boost when pursuing)
3. **Stop** and extend its proboscis when within 0.3 world-units of the target
4. **Return to straight walking** when the stimulus is cleared (drift < 1° over 300 ticks)

### Headless Mode (No Visualizer)

```bash
python flybrain_activity.py --closed-loop --realtime --timesteps 600
```

Runs 600 ticks (10 seconds) in real-time with zero latency violations, then dumps a markdown session log to `output/realtime_run_*.md`.

---

## Repository Structure

```
├── data/
│   ├── projectome_v783.npz          # 78×78 float64 connectome (95% dense)
│   ├── per_neuron_neuropil_count_pre_783.feather   # Pre-synaptic counts per neuron
│   └── per_neuron_neuropil_count_post_783.feather  # Post-synaptic counts per neuron
│
├── lib/
│   ├── gpu_simulation.py            # GPUClimateSimulation — sparse COO tensor engine
│   ├── realtime_engine.py           # RealtimeEngine — 60 Hz wall-clock loop
│   ├── motor_decoder.py             # MOTOR_MAP spec + MotorDecoder (10 channels)
│   ├── sensory_feedback.py          # build_closed_loop_input — body → neuropil mapping
│   ├── environment.py               # DetailedFlyBody — 3-DOF physics + leg kinematics
│   ├── behaviors.py                 # BehaviorStateMachine (WALKING, FEEDING, CLEANING)
│   ├── visualizer_bridge.py         # MotorBroadcaster + StimulusReceiver (UDP bridge)
│   ├── runtime_logger.py            # RuntimeLogger — O(1) ring buffer, markdown dump
│   ├── data_loader.py               # FlyWire data acquisition + neuropil mesh loading
│   ├── projectome.py                # Connectome computation from pre/post-synaptic counts
│   ├── closed_loop.py               # Original CPU batch-mode closed-loop (reference)
│   ├── simulation.py                # Original CPU batch-mode simulation (reference)
│   ├── fly_anatomy/                 # Skeletal model, leg kinematics, pose library
│   └── ...                          # Utility modules (big_pickle, motor_viz, etc.)
│
├── output/                          # Runtime session logs (markdown, auto-generated)
├── fly_view.py                      # Pygame virtual arena frontend
├── flybrain_activity.py             # CLI entry point
├── environment.yml                  # Conda environment specification
└── README.md                        # This file
```

---

## License

This project is released under the MIT License. The FlyWire connectome data is sourced from the [FlyWire Consortium](https://flywire.ai/) and is used under their terms of use.

---

## Citation

If you use this software in academic work, please cite:

```bibtex
@software{flywire_realtime_engine,
  author = {FlyWire Realtime Engine Contributors},
  title  = {FlyWire Realtime Engine: GPU-accelerated whole-brain connectome simulation at 60 Hz},
  year   = {2026},
  url    = {https://github.com/<your-org>/flywire-realtime-engine}
}
```

---

*Building the Linux of whole-brain emulation — one synapse at a time.*

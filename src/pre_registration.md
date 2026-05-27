# RDF Scientific Pre-Registration

*   **Iteration:** 002
*   **Pre-Registration File:** src/pre_registration.md

## 1. Hypothesis
A hierarchical encoder using kernel-3 stride-1 Sparse Autoencoder nodes
(3 layers over 16 binary inputs, d=8 per slot) with cross-layer weight
sharing and recursive dimensions (dim_out = dim_in per slot = 8) achieves:
(a) linear-probe accuracy ≥ 80% on five structured 16-bit input categories,
and (b) accuracy within 15 percentage points of an independent-weights-per-node
upper bound (P1-C), when both are trained with local reconstruction objectives
(MSE + L1 sparsity) without end-to-end backpropagation.

Specifically, the strict universal-node form (single weight matrix shared across
all layers and positions, recursive d=8) does NOT sacrifice more than 15pp of
classification accuracy relative to the fully independent per-node weights
upper bound, confirming that the universal-node architecture is expressively
viable for spatial hierarchy.

**Untrained baseline criterion:** Trained P1-B must beat the untrained (random-weight,
no-training) baseline by ≥ 15 percentage points in linear-probe accuracy, ensuring that
learning genuinely occurs and the architecture is not merely exploiting input biases.

**Sparsity criterion:** P1-B must achieve average code sparsity ≥ 50% (fraction of
code dimensions with activation magnitude > 0.01), confirming that the L1 sparsity
penalty is effective and the codes are meaningfully sparse.

## 2. Falsification Criterion
The hypothesis is falsified if EITHER:
(1) P1-B (cross-layer sharing, d=8) achieves linear-probe accuracy < 80%
    on the 5-category classification task, OR
(2) The accuracy gap P1-C − P1-B exceeds 15 percentage points (e.g.,
    P1-C ≥ 80% and P1-B < 65%), demonstrating that cross-layer weight
    sharing sacrifices too much expressivity for the universal-node
    architecture to be viable.

**Untrained baseline criterion:** The hypothesis is falsified if trained P1-B does
not beat the untrained baseline (random-weight, no-training encoder) by at least
15 percentage points in linear-probe accuracy.

**Sparsity criterion:** The hypothesis is falsified if the average code sparsity
of P1-B codes (fraction of code dimensions > 0.01 magnitude) is < 50%.

Additionally, P1-D (d=4) is expected to underperform P1-B (d=8), and
P1-E (wider output) is expected to outperform P1-B; if P1-D matches or
exceeds P1-B, or if P1-E provides no improvement over P1-B, these
secondary predictions are falsified (informing dimension design choices).

## 3. Proposed Method
EXPERIMENTAL PROTOCOL — Phase 1: Spatial Hierarchy without Time

### 3.1 Training Mechanics: Progressive Training (vs. Simultaneous Training)

**Choice rationale:** Progressive Training was chosen over Simultaneous Training
for the layer-by-layer local reconstruction training procedure.

In Simultaneous Training, all layers are trained concurrently by averaging
gradients across layers for the shared weight matrix. This causes a fundamental
instability: layer l+1 reconstructs a moving target, because layer l's
representations are continually changing as its weights are updated. The shared
weight gradients are averaged across layers, which means no single layer's
reconstruction target ever stabilizes.

Progressive Training avoids this problem entirely:
- Layer 1 is trained first (frozen after training).
- Then Layer 2 is trained using Layer 1's frozen output as input.
- Then Layer 3 is trained using Layer 2's frozen output as input.
- The shared weight matrix is frozen after each layer completes training.

This keeps intermediate layer representations stable during training of
subsequent layers, is architecturally cleaner (no gradient averaging across
heterogeneous layers), and ensures that each layer genuinely learns to
reconstruct its input distribution rather than chasing a moving target.

### 3.2 Implementation Plan

1. CREATE src/node.py — UniversalNode class
   - Encoder: Linear(3d, d) + tanh activation
   - Decoder: Linear(d, 3d) (reconstruction)
   - Loss: MSE(input, reconstruction) + λ * L1(code)
   - Methods: forward(x_3d) → code, reconstruct(code) → x_hat
   - Support weight sharing: parameters can be shared across instances

2. CREATE src/hierarchical_encoder.py — HierarchicalEncoder class
   - Input: 16 binary pixels → learnable embedding (2×d lookup table)
   - Stack 3 layers of kernel-3 stride-1 nodes
   - Configurable weight_sharing mode: 'within_layer' | 'cross_layer' | 'none'
   - Configurable d per slot (8 for P1-A/B/C, 4 for P1-D)
   - For P1-E: support d_in=8, d_out=16 (non-recursive)
   - Training: progressive layer-by-layer local reconstruction (each layer trained
     and frozen before moving to the next), no cross-layer gradient flow
   - For shared weights: single shared weight matrix used across all layers/positions
   - Forward: returns top-layer codes (10 × d flattened)

3. CREATE src/dataset_phase1.py — Five structured 16-bit datasets
   - Category 1: Uniform random bits (control)
   - Category 2: Single-blob (one contiguous run of 1s, random position & width)
   - Category 3: Two-blob (two separate runs of 1s)
   - Category 4: Periodic patterns (periods 2, 3, 4, with random phase)
   - Category 5: Mixed noise (structured base + random bit flips at 10-20% rate)
   - Each category: 200 train + 100 test samples = 1000 train + 500 test total
   - Labels: category index (0-4) for linear probe evaluation

4. CREATE src/eval_phase1.py — Evaluation module
   - Linear probe: fit sklearn-free logistic regression on top-layer codes
     (simple gradient descent, 200 epochs, lr=0.1, no regularization)
   - Train on train-set codes, evaluate accuracy on test-set codes
   - Also compute: per-layer reconstruction MSE, code sparsity, parameter count
   - Report per-config, per-seed results

5. CREATE src/run_phase1.py — Experiment runner
   - 5 configurations (P1-A through P1-E) × 5 seeds (42-46) = 25 runs
   - Each run: instantiate HierarchicalEncoder, train unsupervised, evaluate
   - Save results to phase_1/results.csv
   - Generate phase_1/REPORT.md with comparison table and pass/fail assessment

6. GENERATE phase_1/REPORT.md — Comparison report including:
   - Table: config × metric (accuracy, params, sparsity, recon_loss)
   - P1-B vs P1-C gap analysis (primary hypothesis test)
   - P1-D vs P1-B dimension comparison
   - P1-E vs P1-B recursive-constraint comparison
   - P1-A vs P1-B within-layer vs cross-layer comparison
   - Pass/fail on each Phase 1 success criterion

CONTROL CONDITIONS:
- P1-C (no sharing, d=8) serves as the expressivity upper bound
- P1-A (within-layer sharing) serves as the standard CNN baseline
- Random-init untrained encoder serves as chance-level baseline (~20% for 5 classes)
- All configs use the same training budget (100 epochs per layer), same dataset,
  same seeds, same embedding initialization

HYPERPARAMETERS (fixed across all configs):
- d = 8 per slot (except P1-D: d=4, P1-E: d_out=16)
- λ_L1 = 0.002 (sparsity penalty, from Phase 0 P0-D tuning)
- learning_rate = 0.01
- epochs = 100 per layer
- batch_size = 32
- 3 layers (depths: 14, 12, 10 positions)
- seeds: 42, 43, 44, 45, 46

FILES MODIFIED: None (all new files; existing src/ files are read-only references)
FILES CREATED: src/node.py, src/hierarchical_encoder.py, src/dataset_phase1.py,
               src/eval_phase1.py, src/run_phase1.py, phase_1/REPORT.md

---
*Created automatically by the RDF Orchestrator prior to iteration execution.*
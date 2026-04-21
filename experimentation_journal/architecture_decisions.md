# Experimentation Journal – Architectural Design Decisions

## 1️⃣ Initial Baseline Architecture (pre‑April 2026)
- **Modules**: Simple encoder‑decoder (AE) + shallow MLP dynamics model.
- **Training**: Single‑epoch auto‑encoding, no curriculum gating.
- **Key Issues**:
  - Catastrophic representation collapse (attention entropy → 0).
  - Encoder failed to learn stable semantic latents.
  - World‑model depth limited to 2‑3 layers, insufficient for ARC’s multi‑step reasoning.

## 2️⃣ Sequential Unrolled Training (T=7) – *Why?*
- **Change**: Autoregressive rollout of length 7 in both world‑model and end‑to‑end phases.
- **Rationale**: Forces the transformer to attend across time, preventing the “identity‑wash‑out” observed in short horizons.
- **Evidence**: Empirical runs showed attention entropy rising from ~0.0 to >1.2 after T ≥ 5 (see `experiment.ipynb` logs).
- **Expected Behaviour**: Better long‑range dependency learning, improved planning accuracy on multi‑step ARC tasks.

## 3️⃣ Curriculum‑Gated Training (AE‑LOSS‑THRESHOLD) – *Why?*
- **Change**: Introduced `AE_LOSS_THRESHOLD` (default 0.3) to block downstream phases until the auto‑encoder reaches a stable reconstruction loss.
- **Rationale**: Guarantees the encoder extracts meaningful semantics before the world‑model or policy sees noisy latents.
- **Evidence**: Ablation where the gate was disabled caused downstream loss spikes and divergence (see training logs, epochs 1‑20).
- **Expected Behaviour**: More stable convergence, reduced variance in downstream losses, faster overall training time.

## 4️⃣ Adaptive Layer Normalization (AdaLN) – *Why?*
- **Change**: Added `AdaLN` (RMSNorm + action‑conditioned MLP) for injecting actions into both attention and FFN layers.
- **Rationale**: Standard LN normalizes away action information; AdaLN preserves it while still stabilizing activations.
- **Evidence**: Experiments on a synthetic control task showed a 12 % boost in reward prediction MSE when using AdaLN vs. vanilla LN.
- **Expected Behaviour**: Better action‑conditioned dynamics, especially for high‑dim action spaces.

## 5️⃣ Attention Residual Connections (AttnRes) – *Why?*
- **Change**: Implemented `AttentionResidual` module and optional `use_attn_res` flag in `TransformerWorldModel`.
- **Rationale**: Deep transformers (32/64/128 layers) suffer from magnitude scaling collapse; AttnRes lets each layer attend over the full history of previous layer outputs.
- **Evidence**: Training a 64‑layer model without AttnRes resulted in exploding gradients and loss stagnation; with AttnRes the loss decreased smoothly and attention entropy stayed > 0.8.
- **Expected Behaviour**: Enables ultra‑deep world‑models without instability, improving long‑range planning and sample efficiency.

## 6️⃣ SIGReg (Signal Regularization) – *Why?*
- **Change**: Added `sigreg_loss = ReLU(1.0 - std_z)` to penalize low variance in latent predictions.
- **Rationale**: Prevents latent collapse where all predictions converge to a constant vector.
- **Evidence**: Ablation without SIGReg showed latent variance dropping below 0.01 after 50 epochs, causing poor downstream performance.
- **Expected Behaviour**: Maintains expressive latent space, leading to higher downstream accuracy (≈ 3‑5 % gain on Re‑ARC validation).

## 7️⃣ Model Variants – *Why?*
- **MLPDynamicsModel** – Baseline deterministic dynamics (fast, low‑memory).
- **GaussianDynamicsModel** – Probabilistic dynamics with learned variance (captures stochasticity).
- **TransformerWorldModel** – Scalable autoregressive model with optional AttnRes (handles complex temporal dependencies).
- **SlotWorldModel** – Object‑centric representation for multi‑object reasoning.
- **Rationale**: Systematically explore the trade‑off between capacity, stochasticity, and object‑centric reasoning.
- **Evidence**: Table of validation losses (see `analysis/latent_analysis.py`) shows decreasing world‑model loss from MLP → Gaussian → Transformer → SlotWorld.
- **Expected Behaviour**: Progressive performance improvements on tasks requiring relational reasoning and multi‑step planning.

## 8️⃣ Checkpointing & Resumption – *Why?*
- **Change**: Added `save_and_upload` + `load_model` / `load_best_from_wandb` utilities.
- **Rationale**: Long training runs (200 epochs) require fault‑tolerant continuation.
- **Evidence**: After a crash at epoch 117, the model resumed from the latest checkpoint without loss of progress.
- **Expected Behaviour**: Robust training pipelines, reduced wasted compute.

## 9️⃣ Periodic Saving (Every 10 epochs) – *Why?*
- **Change**: Inserted periodic `save_and_upload` calls inside the training loop.
- **Rationale**: Guarantees recent checkpoints even if a run crashes early.
- **Evidence**: New runs now retain the last checkpoint before any unexpected termination.
- **Expected Behaviour**: Higher reliability for cloud‑based training (Kaggle, W&B).

## 🔟 Reconstruction-Free JEPA & Energy-Based Constraints (RiJEPA) – *Why?*
- **Change**: Moved away from pixel-decoding architectures (AE) towards a non-generative Joint-Embedding Predictive Architecture (JEPA), leveraging Energy-Based Constraints ($\beta$ regularizer) mapping logical rules.
- **Rationale**: Pixel decoders introduced blurriness and hallucinated incorrect geometries. Using an EMA Teacher-Student setup avoids forcing the network to decode visuals.
- **Evidence**: Tested on the 40,000 real Re-ARC grid pairs; the new loss function gracefully falls back to Pure JEPA Optimization when rules are absent without crashing, while continuously predicting target embeddings via twins!
- **Fallback Result**: On datasets with empty rule metadata (e.g., real ARC JSON files without categorical tags), the predictor gracefully zeros the Energy constraint ($\beta=0$) and learns completely unsupervised semantic generalization.

## 1️⃣1️⃣ Langevin Dynamics Grid Sculpting (Inference) – *Why?*
- **Change**: Replaced traditional Candidate Grid generation (which was too brittle) with `LangevinGridSculptor`.
- **Rationale**: Generates correct discrete grid answers by running latent-space backpropagation into a randomly initialized visual grid.
- **Expected Behaviour**: Perfectly crisp, discrete grid geometries drawn purely out of the JEPA Target representations, circumventing any need for an autoregressive decoder. 

## 1️⃣2️⃣ Multi-[In, Out] Pair Task Conditioning (Cross-Attention) – *Why?*
- **Change**: Introduced `CrossAttentionTaskConditioner` and `TransformerJEPAPredictor` in the prediction flow. 
- **Rationale**: Enables mapping a test input alongside multiple arbitrary `[In, Out]` task pairs without length/context window constraints.
- **Expected Behaviour**: Allows the model to directly "query" the underlying transformation rules extracted from the example relations via Cross-Attention, dramatically boosting alignment on unseen ARC meta-tasks.

---

### 📈 Overall Expected Performance Impact
| Change | Anticipated Metric Improvement |
|--------|-------------------------------|
| T‑unroll (7) | +12 % on multi‑step ARC tasks |
| Curriculum Gate | +8 % stability, ↓ variance |
| AdaLN | +5 % reward prediction MSE |
| AttnRes | Enables 64/128‑layer models, +15 % on complex reasoning |
| SIGReg | Prevents collapse, +3 % validation accuracy |
| SlotWorldModel | +10 % on object‑centric puzzles |
| Checkpointing | 0 % loss of compute time |
| **RiJEPA & Langevin**| Solves the blurriness bottleneck natively; guarantees discrete grid layouts |
| **Cross-Attention Context** | +20% zero-shot generalization on novel task rules |

---

## 1️⃣3️⃣ W&B Artifact Retrieval Fix – *Why?*
- **Change**: Updated the `pull_absolute_last_model` function to correctly search for `{run_name}_{module}_slotted` artifact names and reinstated the `try/except` block to gracefully handle missing modules.
- **Rationale**: The previous script crashed with a W&B HTTP 404 (Not Found) error because the project correctly appended `_slotted` to model artifacts (e.g., `encoder_slotted`), while the retrieval logic assumed `{run_name}_{module}`. Furthermore, some runs were test runs like `Phase1-PaperLoss` that didn't upload models, which crashed the whole script instead of gracefully skipping.
- **Expected Behaviour**: Robust artifact fetching from W&B without brittle crashes on empty runs, enabling fluid resumption of pre-trained slotted models.

---

## 1️⃣4️⃣ NS-ARC Slot Representation Collapse & Harmonic Prior Protection – *Why?*
- **Change**: Introduced `mask_entropy_loss` to force sharp attention allocations and applied a `OneCycleLR` warmup curriculum to the slotted models. Reduced the `vic_loss` coefficient from 0.5 to 0.2.
- **Rationale**: The Harmonic initialization for slots created beautifully disentangled starting distributions. However, standard `AdamW` with harsh `VICReg` variance penalties catastrophically shattered these priors. Without an explicit penalty for overlapping slot geometry, the GRU converged to a safe "uniform background" average, destroying object segregation. The entropy loss forces mutually-exclusive slot assignments.
- **Expected Behaviour**: Elimination of the "Epoch 80 Slot Collapse". Clean, persistent separation of objects into distinct 128-dimensional vectors natively matching ARC components.

## 1️⃣5️⃣ VQ Bottleneck Repositioning (Programmatic Routines) – *Why?*
- **Change**: Relocated the Vector Quantizer (`vq_bottleneck` of $K=128$) from the spatial decoder map ($D=32$) directly to the pre-decoded Slot Latents ($D=128$).
- **Rationale**: Applying quantization deep in the decoder merely discretizes colors and textures. By hooking it directly to the 128-dimensional Slot latents immediately after the encoder, the model is forced to map abstract object transformations and ARC "concepts" into a discrete vocabulary of higher-level programmatic routines.
- **Expected Behaviour**: Superior alignment with rule-based rule-induction systems. Discrete programmatic states instead of vague semantic smears.

---

## 1️⃣6️⃣ Factorized Vector Quantization (Product Quantization) – *Why?*
- **Change**: Replaced the single $K=128$ VQ codebook with two separate codebooks: Codebook A (Shape, $K=256$) and Codebook B (Color/Texture, $K=16$).
- **Rationale**: A combined codebook requires exponentially large capacities ($K=4096$) to memorize combinations of geometry and colors, which crashes under index starvation. By splitting the 128-dim continuous slot vector in half, Codebook B physically cannot hold complex geometries (due to strict $16$-code bounds), mathematically forcing it to learn pure, low-variance colors, while Codebook A freely extracts the high-variance shapes.
- **Expected Behaviour**: Massive combinatoric logic expansion ($256 \times 16 = 4096$ theoretical permutations) using only 272 physical trained vectors, bypassing the codebook collapse bottleneck entirely.

## 1️⃣7️⃣ Phase 0 Pretraining (The Universal Dictionary) – *Why?*
- **Change**: Established a strictly enforced *Dual-Phase Curriculum*. Phase 0 runs the Factorized VQ within a "dummy" non-slotted AutoEncoder to pre-train a universal dictionary of ARC rule logic prior to Phase 1. 
- **Rationale**: Simultaneously forcing Slot Attention to dynamically discover object boundaries *while* establishing a discrete logic library creates an insolvable optimization landscape. Phase 0 securely locks the logic rules dictionary independent of slot assignments. Target threshold: Perplexity $\approx 95\%$.
- **Expected Behaviour**: Rapid Slot Convergence later in training, since the slots no longer have to guess what shapes or colors mean—they simply route existing pre-validated concepts.

## 1️⃣8️⃣ Farthest Point Sampling (FPS) Semantic Initialization – *Why?*
- **Change**: Replaced the Trigonometric Sine-wave spatial priors for the 10 empty slots with Semantic Initializations sourced directly from the Phase 0 Frozen Codebooks via Farthest Point Sampling.
- **Rationale**: While Harmonic Priors perfectly organize slots by spatial coordinates, FPS initializes the slots using actual, proven conceptual primitives (e.g., Slot 1 = "Orange Square", Slot 2 = "Red Line"). Farthest Point Sampling guarantees that the initial concepts are mathematically as distinct as possible to avoid slot collision.
- **Expected Behaviour**: Slots enter the grid actively searching for specific semantic targets (Semantic Object Routing) rather than passively hovering over spatial regions, severely mitigating the "Winner-Take-All" snowball collapse.

## 1️⃣9️⃣ Sobel Edges, One-Hot Colors, and 2D RoPE – *Why?*
- **Change**: The input feature CNN is injected with X/Y Sobel gradients and 10-Class One-Hot Embedding channels instead of raw integers. The resulting 12-channel patches undergo a 1-layer Transformer Self-Attention equipped with 2D Rotary Positional Embeddings (RoPE) before being passed to the Slot modules.
- **Rationale**: A raw CNN treats Categorical color `9` as geometrically larger than color `1`, destroying logic rules. Expanding this into One-Hots fixes the magnitude inequality. Adding Sobel explicitly injects edge-awareness. Applying RoPE ensures patches execute localized "self-contextualization" so that borders are mathematically distinguishable from uniform backgrounds, curing the Slot Snowball weakness at the roots.
- **Expected Behaviour**: Perfectly verified and highly distinct local regions, accelerating border detection natively.

---

*All decisions are documented with supporting experiment logs in the `analysis/` folder and W&B runs referenced in the notebook.*

# COMPLETE FEDERATED CONTINUAL SELF-SUPERVISED VISION PIPELINE
## Federated Continual Self-Supervised Vision via Gated Prototype Anchored Distillation
### Full Implementation Guide with All Enhancements

> Update note:
> The executable source of truth is now `main.py`, `new_main.py`, and the
> files under `src/`. This guide is retained as a broad research note, but the
> current implementation uses the corrected GPAD gradient flow, server-to-client
> weight broadcast, unified embedding extraction, non-dropping sample
> allocation, and the 4-dataset sequential benchmark described in the README.
> Sections in this document that discuss optional confidence-scoring
> enhancements should be read as historical research notes rather than
> executable features in the current codebase.

---

## TABLE OF CONTENTS

1. Problem Formulation & Motivation
2. System Architecture Overview
3. Complete Step-by-Step Pipeline (0-8)
4. Enhanced Components (6 Enhancements)
5. Mathematical Formulations
6. Implementation Details
7. Experimental Setup
8. Evaluation Metrics
9. Timeline & Deliverables
10. Publication Strategy

---

# 1. PROBLEM FORMULATION & MOTIVATION

## The Challenge

You have a distributed federated learning environment where:
- **Multiple clients** have decentralized, unlabeled, non-IID vision data
- **Privacy constraints** prevent sharing raw data
- **Continual learning requirement**: New tasks arrive sequentially; models must learn without forgetting old tasks
- **Resource constraints**: Edge devices have limited communication and compute

Traditional solutions fail:
- ❌ Centralized learning: violates privacy
- ❌ Standard FedAvg: doesn't handle sequential tasks (catastrophic forgetting)
- ❌ Centralized continual learning: requires labeled data
- ❌ Individual client training: loses collaborative knowledge

## Your Solution

A novel framework combining:
1. **Self-Supervised Pretraining** (MAE): Learn from unlabeled data
2. **Federated Aggregation**: Share knowledge without exposing data
3. **Prototype-Based Memory**: Compact semantic representation
4. **Gated Distillation**: Adaptive knowledge transfer with confidence weighting
5. **Continual Learning**: Evolving prototypes across tasks

---

# 2. SYSTEM ARCHITECTURE OVERVIEW

```
┌──────────────────────────────────────────────────────────────┐
│   FEDERATED CONTINUAL SELF-SUPERVISED VISION SYSTEM          │
├──────────────────────────────────────────────────────────────┤
│                                                               │
│  ┌─────────────────────────────────────────────────────┐     │
│  │ LAYER 1: Self-Supervised Pretraining (SSL)          │     │
│  │ - Masked Image Modeling (MAE) on unlabeled data      │     │
│  │ - Federated aggregation of encoder weights           │     │
│  │ - Output: Learned visual backbone                    │     │
│  └─────────────────────────────────────────────────────┘     │
│                          ↓                                    │
│  ┌─────────────────────────────────────────────────────┐     │
│  │ LAYER 2: Parameter-Efficient Fine-Tuning            │     │
│  │ - Vision Transformer (ViT) backbone (FROZEN)         │     │
│  │ - Task-specific adapters or LoRA modules             │     │
│  │ - Only 2-5% of parameters trainable                  │     │
│  └─────────────────────────────────────────────────────┘     │
│                          ↓                                    │
│  ┌─────────────────────────────────────────────────────┐     │
│  │ LAYER 3: Prototype-Based Knowledge Distillation      │     │
│  │ - Local prototype extraction (k-means clustering)     │     │
│  │ - Global prototype aggregation (weighted merging)     │     │
│  │ - Gated confidence-weighted distillation loss         │     │
│  └─────────────────────────────────────────────────────┘     │
│                          ↓                                    │
│  ┌─────────────────────────────────────────────────────┐     │
│  │ LAYER 4: Continual Learning Memory                   │     │
│  │ - Experience replay with uncertainty sampling         │     │
│  │ - Novelty detection and dynamic prototype expansion   │     │
│  │ - Catastrophic forgetting prevention                 │     │
│  └─────────────────────────────────────────────────────┘     │
│                          ↓                                    │
│  ┌─────────────────────────────────────────────────────┐     │
│  │ LAYER 5: Evaluation & Analysis                       │     │
│  │ - Per-task accuracy tracking                         │     │
│  │ - Forgetting and backward transfer metrics           │     │
│  │ - Communication efficiency analysis                  │     │
│  └─────────────────────────────────────────────────────┘     │
│                                                               │
└──────────────────────────────────────────────────────────────┘

```python
```
# 5. MATHEMATICAL FORMULATIONS

## 5.1 Local Prototype Computation (STEP 1)

```
Given: Local embeddings Z = {z_1, ..., z_N} ∈ R^(N×d)
Output: Local prototypes P = {μ_1, ..., μ_K}

1. Normalize: Z_norm = Z / ||Z||_2
2. K-means clustering: C_1, ..., C_K = KMeans(Z_norm, k=K)
3. Prototype computation: μ_k = mean(Z_norm[C_k])
4. Normalize: μ_k = μ_k / ||μ_k||_2
5. Store counts: n_k = |C_k|
```

## 5.2 Global Prototype Aggregation (STEP 2)

```
Given: Client prototypes {P^(i) : i=1..M}, {C^(i) : counts}
Output: Global prototypes G

Bootstrap (Round 1):
1. Concatenate: P_all = ∪_i P^(i)
2. Similarity matrix: S[i,j] = cos(P_all[i], P_all[j])
3. Redundancy removal:
   For each prototype p:
     Find similar: {q : cos(p,q) > τ_merge}
     Merge: μ_merged = (Σ n_q · q) / Σ n_q
     Replace cluster with single prototype
4. Result: G = merged prototypes
```

## 5.3 Gated Prototype Distillation Loss (STEP 5.3)

```
Given: Embedding z, global prototypes G, similarity s = cos(z, G[k*])
       where k* = argmax_k cos(z, G[k])

Soft Gating Loss (RECOMMENDED):

1. Normalize: z_norm = z / ||z||_2

2. Compute confidence-weighted gate:
   gate = sigmoid((s - τ_adaptive) / T)
   where τ_adaptive = τ_base - λ·H(z)
         H(z) = entropy of z over prototypes
         T = temperature (0.07)

3. Prototype loss:
   L_proto = gate · ||z_norm - G[k*]_norm||_2

4. Combined loss (curriculum scheduled):
   L_total = L_CE + λ_proto(round) · L_proto
   where λ_proto(round) = { 0.1·round/5 if round < 5}
                           { 1.0         otherwise}
```

## 5.4 Confidence Score Computation (ENHANCEMENT 1)

```
For each prototype μ_k:

Confidence_k = (count_k / Σ count_i) × (1 - var_k / max_var)

where:
  - count_k: number of samples contributing to μ_k
  - var_k: variance of samples around μ_k (estimated as distance std)
  - Normalized to [0, 1]

Use in gating:
  gate = proto_confidence[k*] × sigmoid(...)
```

---

# 6. IMPLEMENTATION DETAILS

## 6.1 Configuration Template

```python
config = {
    # Model
    'vit_model': 'vit_base_patch16',
    'embedding_dim': 768,
    'num_adapters': 12,
    'adapter_hidden_dim': 64,
    
    # Data
    'num_clients': 10,
    'num_tasks': 5,
    'classes_per_task': 20,
    'dirichlet_alpha': 0.5,  # Non-IID parameter (lower = more non-IID)
    'batch_size': 32,
    
    # Prototypes
    'K': 20,  # Number of local prototypes per client
    'prototype_merge_threshold': 0.85,  # Redundancy removal threshold
    'alpha_ema': 0.1,  # EMA update rate
    'novelty_threshold': 0.4,  # Below this = novel
    'novelty_buffer_size': 500,
    
    # Training
    'local_epochs': 10,
    'total_rounds': 100,  # Per task
    'learning_rate': 0.001,
    'temperature': 0.07,
    
    # Losses
    'lambda_proto': 0.5,  # Prototype distillation weight (with curriculum)
    'gating_type': 'soft_sigmoid',  # soft_sigmoid, confidence_weighted, soft_assignment
    'tau_threshold': 0.5,
    
    # Communication
    'client_fraction': 0.8,  # Fraction of clients per round
    'use_compression': False,
    
    # Enhancements
    'enable_confidence_scoring': True,  # Enhancement 1
    'enable_denoising': True,  # Enhancement 2 (every 10 rounds)
    'enable_task_aware_tags': True,  # Enhancement 3
    'enable_adaptive_gating': True,  # Enhancement 4
    'enable_differential_privacy': False,  # Enhancement 5 (optional)
    'enable_optimal_transport': False,  # Enhancement 6 (optional, slower)
}
```

## 6.2 Key Hyperparameters

```
Critical Hyperparameters (tune these):

1. alpha_ema [0.05 - 0.2]
   - Recommendation: 0.1 (medium stability)
   - Lower: more stable but slow adaptation
   - Higher: faster adaptation, more noise

2. novelty_threshold [0.3 - 0.6]
   - Recommendation: 0.4
   - Affects how many samples are deemed "novel"
   - Too high: miss real novelty
   - Too low: false positives

3. prototype_merge_threshold [0.80 - 0.95]
   - Recommendation: 0.85
   - How similar before merging in STEP 2
   - Affects global prototype bank size

4. lambda_proto_schedule
   - Recommendation: 0.1 * round for first 5 rounds, then 1.0
   - Prevents prototype noise from early learning

5. temperature (gating) [0.05 - 0.15]
   - Recommendation: 0.07
   - Standard in contrastive learning
   - Controls softness of gating

6. tau_threshold [0.3 - 0.7]
   - Recommendation: 0.5
   - Adaptive gating: reduced by uncertainty
   - Sets confidence bar for prototype matching
```

---

# 7. EXPERIMENTAL SETUP

## 7.1 Datasets & Splits

Current repository experiments:

```python
# Baseline experiment in main.py
- Dataset: Tiny ImageNet
- 200 classes, 100K train images
- Image size: 64x64 resized to 224x224 for ViT-MAE
- Non-IID split: Dirichlet allocation across 2 clients
- Round schedule: 5 rounds x 40 classes per round by default

# Sequential experiment in new_main.py
- Client 0: EuroSAT, PCAM
- Client 1: Oxford-IIIT Pet, Flowers102
- Each client completes one dataset before moving to the next
- The sequence intentionally spans satellite, medical, pet-recognition,
  and flower-classification domains
- Finished stage datasets are deleted after evaluation to reduce local storage
```

The older example block below is retained as a generic research note only.

```python
# Legacy example block: see the updated repository experiment summary above
- This legacy note is not the current executable setup
- The current baseline uses Tiny ImageNet across 2 clients
- All datasets are resized to 224x224 and normalized for ViT-MAE
- See README.md for the maintained dataset list and output artifacts

# Current baseline summary
- Tiny ImageNet remains the baseline dataset in main.py
- The baseline uses a Dirichlet non-IID split and round-wise class scheduling
- The sequential benchmark is implemented separately in new_main.py

# For current domain-shift experiments:
- The repository now uses the 4-dataset sequence listed above
- Each client completes one dataset before moving to the next
```

## 7.2 Evaluation Protocol

```python
# Current new_main.py evaluation flow:
1. Linear-probe accuracy on the current stage datasets
2. Average stage accuracy across the active datasets
3. Final per-dataset accuracy summary at the end of the run
4. Forgetting is not computed in the storage-saving workflow because finished datasets are deleted after each stage

# Communication tracking:
1. Bytes sent per round (adapters + prototypes)
2. Compression ratio (if applicable)
3. Total communication cost vs baselines

# Computational cost:
1. Training time per round
2. Inference latency
3. Memory usage per client
```

## 7.3 Baseline Comparisons

```
1. FedAvg (standard federated averaging)
   - No prototypes, no continual handling
   - Baseline: expect 45-55% accuracy

2. FedAvg + Replay (experience replay only)
   - No prototypes, simple replay buffer
   - Expected: 55-65% accuracy

3. FedProto (prototype-based FL)
   - Class prototypes (needs labels)
   - Expected: 65-70% accuracy

4. FedGPD (global prototype distillation)
   - Supervised prototype distillation
   - Expected: 70-75% accuracy

5. FedAli (optimal transport alignment)
   - State-of-art prototype FL
   - Expected: 72-75% accuracy

6. V-LETO (vertical FCL with prototypes)
   - Closest to yours (but vertical FL)
   - Expected: 74-76% accuracy

7. Your Method (Full)
   - Expected: 75-78% accuracy
   - With all 6 enhancements: 78-82%
```

---

# 8. EVALUATION METRICS

## 8.1 Accuracy Metrics

```python
class AccuracyTracker:
    def __init__(self, num_tasks):
        self.task_accuracies = {}  # {task_id: [acc_after_task0, acc_after_task1, ...]}
        self.num_tasks = num_tasks
    
    def compute_average_accuracy(self):
        """Average accuracy across all tasks"""
        flat = [acc for accs in self.task_accuracies.values() for acc in accs]
        return np.mean(flat)
    
    def compute_forgetting(self):
        """Backward forgetting: how much did old tasks degrade"""
        forgetting_per_task = []
        for task_id in range(self.num_tasks - 1):  # Exclude last task
            # Accuracy on task_id immediately after learning
            acc_after = self.task_accuracies[task_id][task_id]
            # Best accuracy on task_id after all subsequent tasks
            acc_best_later = max(self.task_accuracies[j][task_id] 
                                for j in range(task_id + 1, self.num_tasks))
            forgetting = acc_after - acc_best_later
            forgetting_per_task.append(forgetting)
        
        return np.mean(forgetting_per_task)
    
    def compute_backward_transfer(self):
        """Does learning new tasks help old tasks?"""
        transfer = 0
        for task_id in range(self.num_tasks - 1):
            # Change in accuracy on old task after learning all subsequent tasks
            change = (self.task_accuracies[self.num_tasks-1][task_id] -
                     self.task_accuracies[task_id][task_id])
            transfer += change
        
        return transfer / (self.num_tasks - 1)
```

## 8.2 Communication Efficiency

```python
# Bytes transmitted per round per client:
# Adapters: 12 layers × 64×768 + 768×64 = ~600 KB (LoRA: ~100 KB)
# Prototypes: 20 × 768 × 4 bytes = ~60 KB
# Total: ~660 KB per round

# Communication reduction vs baseline:
# FedAvg (full ViT): 350 MB
# Your method: 0.66 MB
# Reduction: ~500x or 0.2% of full model communication

# Track over all rounds:
total_bytes = sum_over_all_rounds(adapter_bytes + prototype_bytes)
reduction_factor = total_bytes / (full_model_bytes * num_rounds)
```

---

---

# 10. PUBLICATION STRATEGY

## Paper Structure

```
1. Abstract (150 words)
   - Problem: FCL with privacy + heterogeneity
   - Solution: Gated prototype distillation
   - Results: +30% over FedAvg, -80% forgetting

2. Introduction
   - Federated learning challenges
   - Continual learning challenges
   - State-of-art (mention FedProto, FedGPD, V-LETO)
   - Your contribution: gated mechanism + MAE

3. Related Work
   - Federated Learning (FedAvg, FedProto, FedGPD)
   - Continual Learning (EWC, replay, prototypes)
   - Self-Supervised Learning (MAE, BEiT)
   - Combined approaches

4. Method
   - Problem formulation & motivation
   - Complete pipeline (Steps 0-8) with math
   - 6 enhancements (as extensions)
   - Loss functions and algorithms

5. Experiments
   - Dataset & setup
   - Baselines & ablations
   - Main results table
   - Non-IID robustness
   - Communication analysis

6. Results & Analysis
   - Accuracy trends
   - Forgetting reduction
   - Ablation study
   - Communication efficiency
   - Visualizations (t-SNE of prototypes)

7. Discussion
   - Why gated mechanism helps
   - Comparison to baselines
   - Limitations
   - Future work

8. Conclusion

9. References (40-50 papers)

10. Appendix
    - Detailed algorithms
    - Hyperparameter tuning
    - Additional results
    - Implementation details
```

## Key Differentiators for Reviewers

1. **Novel gated mechanism** - soft sigmoid/confidence weighting never done before
2. **Cluster prototypes** - no labels needed (unsupervised)
3. **Comprehensive ablations** - proves each component matters
4. **Strong baselines** - compare to FedProto, FedGPD, FedAli
5. **6 enhancements** - shows depth of investigation
6. **Communication analysis** - shows practical applicability

---

# SUMMARY

This complete pipeline represents a novel, publication-quality research contribution combining:

- **MAE-based self-supervised pretraining** (STEP 0-1)
- **Federated prototype aggregation** (STEP 2, 8)
- **Gated confidence-weighted distillation** (STEP 5.3) - YOUR KEY INNOVATION
- **Continual learning with dynamic prototypes** (STEP 6)
- **6 research enhancements** (confidence scoring, denoising, task-awareness, adaptive gating, DP, optimal transport)

**Expected Results:**
- Base method: 74-75% accuracy
- With all 6 enhancements: 78-82% accuracy
- Forgetting reduction: -80% vs FedAvg
- Communication efficiency: 500× reduction

**Timeline:** 16 weeks (realistic for final-year project)

**Publication Potential:** IJCAI/AAAI main or top workshop with proper experiments and ablations.

---

This is your complete, industry-grade research project. Good luck! 🚀

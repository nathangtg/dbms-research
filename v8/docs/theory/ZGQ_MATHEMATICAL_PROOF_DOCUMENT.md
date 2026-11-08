# Zonal Graph Quantization (ZGQ): Mathematical Proof of Concept

> **Status: historical draft (October 2025).** The analytic derivations are kept for reference.
> The empirical figures in this file (for example hop counts, alpha, latency and recall
> tables) come from earlier unreproducible runs and are superseded by `v8/docs/BENCHMARKS.md`
> and `v8/results/2026-11-08/summary.json`. The canonical benchmark does not support
> Lemma 6.1 or Theorem 6.2 at 100K and 1M vectors; see `v8/docs/THEORY.md`.

## Document Information
- **Project**: Zonal Graph Quantization for Scalable Vector Search
- **Authors**: Nathan Aldyth Prananta Ginting, Jordan Chay Ming Hong, Jaeden Ting YiYong
- **Affiliation**: Faculty of Engineering and Technology, Sunway University
- **Version**: 1.0
- **Date**: October 2025

---

## Executive Summary

This document provides rigorous mathematical proofs and theoretical validation for the Zonal Graph Quantization (ZGQ) framework—a novel hybrid approach to Approximate Nearest Neighbor Search (ANNS) that achieves superior memory-performance trade-offs compared to state-of-the-art methods. Through formal complexity analysis, we demonstrate that:

- **Space Complexity**: ZGQ maintains O(N·M·d) memory usage with vanishing O(√N·d) overhead
- **Query Complexity**: ZGQ achieves O(√N·d + α log N·d) time with α ≈ 0.74 < 1 path reduction factor
- **Empirical Validation**: 1.35× speedup over pure HNSW with <1% memory overhead at scale

---

## Table of Contents

1. [Introduction and Problem Formulation](#1-introduction-and-problem-formulation)
2. [Foundational Definitions](#2-foundational-definitions)
3. [ZGQ Architecture and Design Principles](#3-zgq-architecture-and-design-principles)
4. [Theoretical Complexity Analysis](#4-theoretical-complexity-analysis)
5. [Proof of Space Efficiency](#5-proof-of-space-efficiency)
6. [Proof of Query Time Optimization](#6-proof-of-query-time-optimization)
7. [Proof of Optimal Zone Count](#7-proof-of-optimal-zone-count)
8. [Comparative Analysis](#8-comparative-analysis)
9. [Empirical Validation](#9-empirical-validation)
10. [Conclusion](#10-conclusion)

---

## 1. Introduction and Problem Formulation

### 1.1 Problem Statement

Given:
- A dataset **D** = {x₁, x₂, ..., xₙ} where xᵢ ∈ ℝᵈ (d-dimensional vectors)
- A query vector **q** ∈ ℝᵈ
- An integer k ≥ 1

**Objective**: Find k approximate nearest neighbors of q in D that minimize:
1. **Query Latency** T_query
2. **Memory Footprint** S_index
3. **Construction Time** T_build

Subject to maintaining acceptable **Recall@k** ≥ target_recall (typically ≥ 0.90)

### 1.2 Existing Approaches and Limitations

#### 1.2.1 Pure Graph Methods (HNSW)
**Advantages**:
- Fast queries: O(log N · ef · d)
- High recall: 90-95% achievable

**Limitations**:
- High memory: O(N · M · d) where M = 16-32
- Expensive construction: O(N log N · M · d)
- No spatial awareness in graph structure

#### 1.2.2 Pure Partitioning Methods (IVF, IVF-PQ)
**Advantages**:
- Memory efficient: O(N · d) or O(N · b) with compression
- Fast construction: O(K_iter · N · Z · d)

**Limitations**:
- Slow queries: O(N/Z · n_probe · d) linear scan
- Lower recall: 40-60% typical
- Zone boundary effects

### 1.3 ZGQ Hypothesis

**Central Hypothesis**: By organizing data spatially *before* constructing a unified HNSW graph, we create an inherently better-structured topology that enables:
- Faster graph navigation (reduced path length)
- Comparable memory to pure HNSW
- Superior performance to IVF methods

---

## 2. Foundational Definitions

### Definition 2.1: Zone-Aware Partition

Given dataset D ⊂ ℝᵈ, a **zone-aware partition** is a mapping φ: D → {1, 2, ..., Z} induced by K-Means clustering with centroids C = {c₁, c₂, ..., c_Z}, where:

```
φ(x) = argmin_{i∈[Z]} ‖x - cᵢ‖₂²
```

The K-Means objective minimizes intra-zone variance:

```
L(C) = Σⱼ₌₁ᶻ Σ_{x∈Zⱼ} ‖x - cⱼ‖₂²
```

where Zⱼ = {x ∈ D : φ(x) = j}

### Definition 2.2: Zone Entry Point

For each zone j ∈ [Z], the **entry point** eⱼ is the vector in Zⱼ closest to centroid cⱼ:

```
eⱼ = argmin_{x∈Zⱼ} ‖x - cⱼ‖₂²
```

### Definition 2.3: Unified HNSW Graph with Zone Metadata

A **ZGQ index** I = (G, φ, C, E) consists of:
- **G**: Single unified HNSW graph where V = D (all vectors)
- **φ**: Zone assignment function
- **C**: Set of zone centroids {c₁, ..., c_Z}
- **E**: Set of entry points {e₁, ..., e_Z}

**Key Property**: Vectors are inserted into G in *zone-sorted order*, creating spatial locality in graph structure.

### Definition 2.4: Distance Metrics

All operations use **L2 (Euclidean) distance**:

```
d(x, y) = ‖x - y‖₂ = √(Σᵢ₌₁ᵈ (xᵢ - yᵢ)²)
```

For efficiency, we use **squared distance** during comparisons:

```
d²(x, y) = ‖x - y‖₂² = Σᵢ₌₁ᵈ (xᵢ - yᵢ)²
```

---

## 3. ZGQ Architecture and Design Principles

### 3.1 Construction Algorithm

**Algorithm 1: ZGQ Index Construction**

```
Input: Dataset D with N vectors, dimension d, number of zones Z
Output: ZGQ index I = (G, φ, C, E)

Phase 1: Zonal Partitioning
1. Run K-Means clustering on D with Z clusters
2. Obtain zone assignments φ and centroids C = {c₁, ..., c_Z}

Phase 2: Compute Entry Points
3. For each zone j = 1 to Z:
4.     Zⱼ ← {x ∈ D : φ(x) = j}
5.     eⱼ ← argmin_{x∈Zⱼ} ‖x - cⱼ‖₂²
6. E ← {e₁, ..., e_Z}

Phase 3: Build Unified HNSW Graph
7. D_sorted ← sort(D, key=φ)  // Sort by zone
8. Initialize empty HNSW graph G
9. For each x in D_sorted:
10.    G.add_item(x)  // Insert in zone-sorted order

Return I = (G, φ, C, E)
```

**Time Complexity**:
- Phase 1: O(K_iter · N · Z · d) using Mini-Batch K-Means
- Phase 2: O(N · d)
- Phase 3: O(N log N · M · d)
- **Total**: O(N log N · M · d) when using Mini-Batch K-Means

### 3.2 Search Algorithm

**Algorithm 2: ZGQ k-NN Search**

```
Input: Query q, index I, k, n_probe, ef_search
Output: Top-k nearest neighbors

// Fast Path: Single-Zone Search
If n_probe = 1:
    1. Perform HNSW search: (I, D) ← G.knn_query(q, k, ef_search)
    2. Return (I, D)

// High-Recall Path: Multi-Zone Search
Else:
    1. Compute distances to all centroids:
       dist[j] ← ‖q - cⱼ‖₂² for j ∈ [Z]
    
    2. Select nearest zones:
       P ← argmin_{n_probe}(dist)  // Top n_probe zones
    
    3. Perform expanded HNSW search:
       k' ← min(k · n_probe, N)
       (I, D) ← G.knn_query(q, k', ef_search)
    
    4. Filter to selected zones:
       mask ← [φ(I[i]) ∈ P for i in [k']]
       I_filtered ← I[mask]
       D_filtered ← D[mask]
    
    5. Return top-k:
       Return (I_filtered[:k], D_filtered[:k])
```

**Time Complexity**:
- Zone selection: O(Z · d + n_probe log n_probe)
- HNSW search: O(log N · ef · d)
- Filtering: O(k · n_probe)
- **Total**: O(Z · d + log N · ef · d)

### 3.3 Key Design Principles

1. **Spatial Locality Through Ordering**: Zone-sorted insertion creates clustered neighborhoods
2. **Single Unified Graph**: Avoids overhead of managing multiple independent graphs
3. **Flexible Search Modes**: Fast single-zone vs. high-recall multi-zone
4. **Minimal Overhead**: Zone metadata scales as O(√N · d) when Z = √N

---

## 4. Theoretical Complexity Analysis

### 4.1 Notation and Assumptions

**Notation**:
- N: Number of vectors in dataset
- d: Dimension of vectors
- Z: Number of zones
- M: Average degree in HNSW graph (typically 16)
- ef: HNSW exploration factor during search
- k: Number of nearest neighbors to return
- n_probe: Number of zones to search

**Assumptions**:
1. K-Means converges in K_iter = O(1) iterations (using Mini-Batch)
2. HNSW provides O(log N) expected search complexity
3. Zones are approximately balanced: |Zⱼ| ≈ N/Z
4. Distance computations dominate runtime: O(d) per computation

---

## 5. Proof of Space Efficiency

### Theorem 5.1: ZGQ Space Complexity

**Statement**: The space complexity of ZGQ with N vectors, dimension d, Z zones, and average HNSW degree M is:

```
S_ZGQ = O(N · d + N · M + Z · d)
```

For Z = Θ(√N), this simplifies to:

```
S_ZGQ = O(N · d + N · M) = O(N · (d + M))
```

**Proof**:

The space is partitioned into three components:

#### Component 1: Vector Storage
- Store N vectors, each of dimension d
- Each vector: d floating-point numbers (typically 4 bytes each)
- **Space**: O(N · d)

#### Component 2: HNSW Graph Structure
- Unified graph G has N nodes
- Each node maintains M bidirectional edges on average
- Each edge: 1 integer ID (4 bytes)
- Total edges: N · M integers
- **Space**: O(N · M)

#### Component 3: Zone Metadata
- **Centroids**: Z vectors of dimension d = O(Z · d)
- **Zone assignments**: N integers = O(N)
- **Entry points**: Z integers = O(Z)
- **Inverse indices** (optional): Z lists with total N entries = O(N)

Total metadata: O(Z · d + N + Z) = O(Z · d + N)

For d > 1 (always true in practice), centroid storage dominates:
**Space**: O(Z · d)

#### Total Space
```
S_ZGQ = O(N · d) + O(N · M) + O(Z · d)
      = O(N · (d + M) + Z · d)
```

#### Asymptotic Analysis for Z = √N

When Z = Θ(√N):
```
S_ZGQ = O(N · (d + M) + √N · d)
```

The √N · d term grows slower than N · (d + M):
```
lim_{N→∞} (√N · d)/(N · (d + M)) = lim_{N→∞} d/(√N · (d + M)) = 0
```

Therefore, the centroid overhead is asymptotically negligible:
```
S_ZGQ = O(N · (d + M))
```

This is **identical** to pure HNSW space complexity. ∎

### Corollary 5.1: Memory Overhead vs Pure HNSW

**Statement**: The memory overhead of ZGQ compared to pure HNSW is:

```
ΔS = O(Z · d + N) = O(√N · d) for Z = √N
```

As a fraction of total space:

```
ΔS / S_HNSW = O(√N · d) / O(N · (d + M))
             = O(1/√N)
             → 0 as N → ∞
```

**Proof**: Direct calculation from Theorem 5.1.

Pure HNSW requires: S_HNSW = O(N · (d + M))

ZGQ additional components: O(Z · d + N)

Overhead fraction:
```
ΔS / S_HNSW = (Z · d + N) / (N · (d + M))
```

For Z = √N:
```
ΔS / S_HNSW = (√N · d + N) / (N · (d + M))
             = d/(√N · (d + M)) + 1/(d + M)
```

As N → ∞, the first term → 0, second term is constant:
```
ΔS / S_HNSW → 1/(d + M) ≈ 1/144 < 1% for d=128, M=16
```

**Empirical Validation**:
- N = 10⁴: Overhead = 64% (small scale)
- N = 10⁵: Overhead = 0.8%
- N = 10⁶: Overhead = 0.7%

The √N scaling is empirically confirmed. ∎

---

## 6. Proof of Query Time Optimization

### Theorem 6.1: ZGQ Query Complexity

**Statement**: The expected time complexity for a single k-NN query in ZGQ is:

```
T_ZGQ = O(Z · d + log N · ef · d + k log k)
```

For Z = Θ(√N) and constant ef:
```
T_ZGQ = O(√N · d + log N · d)
```

**Proof**:

The query algorithm proceeds in three phases:

#### Phase 1: Zone Selection (Optional)

For n_probe = 1 (fast mode), this phase is skipped entirely.

For n_probe > 1:
- Compute distance from query q to all Z centroids
- Each distance: O(d) operations
- Total: Z distance computations = O(Z · d)
- Select top n_probe using partial sort: O(Z + n_probe log n_probe)

For constant n_probe:
**Phase 1 Time**: O(Z · d)

#### Phase 2: Unified HNSW Search

This is the critical phase where ZGQ's advantage manifests.

**Standard HNSW Complexity**:
- Expected hops: O(log N)
- Per hop: evaluate ef candidates
- Per candidate: O(d) distance computation
- **Standard**: O(log N · ef · d)

**ZGQ Enhancement - Path Reduction**:

Zone-aware construction creates spatial locality. Define:
- L(G_HNSW): Expected path length in pure HNSW
- L(G_ZGQ): Expected path length in zone-aware graph

**Key Observation**: Zone-sorted insertion ensures:
1. Intra-zone edges dominate local neighborhoods
2. Inter-zone edges connect adjacent (nearby) zones
3. Entry points provide better initialization

This leads to **shorter greedy paths**:

```
L(G_ZGQ) ≤ α · L(G_HNSW)
```

where α < 1 is the path reduction factor.

**Empirical Measurement**: α ≈ 0.74 (26% reduction)

**Phase 2 Time**: O(α · log N · ef · d)

#### Phase 3: Result Processing

For n_probe = 1:
- HNSW returns k results pre-sorted by hnswlib
- **Time**: O(k) (just array copy)

For n_probe > 1:
- Merge n_probe · k candidates
- Use heap to extract top k
- **Time**: O(n_probe · k · log k)

For constant n_probe:
**Phase 3 Time**: O(k log k)

#### Combined Complexity

```
T_ZGQ = O(Z · d) + O(α · log N · ef · d) + O(k log k)
```

For typical parameters (Z = √N, ef = 50, k = 10, α = 0.74):
```
T_ZGQ = O(√N · d + 0.74 · log N · d + 10 log 10)
```

The log N term (with reduced coefficient) dominates for N > 10⁴:
```
T_ZGQ = O(√N · d + α · log N · d)
```

∎

### Lemma 6.1: Path Reduction Effect

**Statement**: Let G_HNSW be a pure HNSW graph and G_ZGQ be a zone-aware HNSW graph on the same dataset. Under the assumption that spatial locality in insertion order reduces edge lengths, the expected number of hops satisfies:

```
E[h_ZGQ(q)] ≤ α · E[h_HNSW(q)]
```

where α < 1 depends on data distribution and zone quality.

**Proof Sketch**:

Define **zone coherence** of a path P = (v₁, v₂, ..., vₕ):

```
ρ(P) = (1/(h-1)) · Σᵢ₌₁ʰ⁻¹ 𝟙[φ(vᵢ) = φ(vᵢ₊₁)]
```

Zone-aware construction maximizes ρ(P) by:
1. Inserting spatially close vectors consecutively
2. Creating dense intra-zone connectivity
3. Establishing inter-zone shortcuts between adjacent zones

For a query targeting zone j*:
- **Initialization**: Entry point eⱼ* provides proximity (vs. random start)
- **Navigation**: High intra-zone density reduces hops to reach target
- **Shortcuts**: Inter-zone edges enable efficient long-range moves

**Empirical Analysis** (on 10K-1M vectors, d=128):
- Pure HNSW: Average hops ≈ 13.2
- ZGQ: Average hops ≈ 9.8
- Reduction: α ≈ 9.8/13.2 ≈ 0.74

The path reduction translates directly to speedup:
```
Speedup = 1/α ≈ 1/0.74 ≈ 1.35×
```

∎

### Theorem 6.2: ZGQ vs HNSW Query Time Comparison

**Statement**: For datasets with N > 10⁴, ZGQ achieves faster queries than pure HNSW despite zone selection overhead:

```
T_ZGQ < T_HNSW
```

when α < 1 - (√N · d)/(log N · ef · d)

**Proof**:

Pure HNSW query time:
```
T_HNSW = O(log N · ef · d)
```

ZGQ query time:
```
T_ZGQ = O(Z · d + α · log N · ef · d)
```

For Z = √N:
```
T_ZGQ = O(√N · d + α · log N · ef · d)
```

ZGQ is faster when:
```
√N · d + α · log N · ef · d < log N · ef · d

√N · d < (1 - α) · log N · ef · d

α < 1 - √N/(log N · ef)
```

**Numerical Example** (N = 10⁴, ef = 50, α = 0.74):
```
Right side: 1 - √10000/(log₂(10000) · 50)
         = 1 - 100/(13.3 · 50)
         = 1 - 100/665
         = 1 - 0.15
         = 0.85

Since 0.74 < 0.85, condition satisfied ✓
```

**Empirical Validation**:
- N = 10⁴: T_ZGQ = 0.053 ms, T_HNSW = 0.071 ms → 1.34× faster ✓
- N = 10⁵: T_ZGQ = 0.060 ms, T_HNSW = 0.080 ms → 1.33× faster ✓
- N = 10⁶: T_ZGQ = 0.090 ms, T_HNSW = 0.120 ms → 1.33× faster ✓

∎

---

## 7. Proof of Optimal Zone Count

### Theorem 7.1: Optimal Zone Count

**Statement**: To minimize query latency while maintaining build efficiency, the optimal number of zones is:

```
Z* = Θ(√N)
```

**Proof**:

Query time from Theorem 6.1:
```
T_ZGQ = c₁ · Z · d + c₂ · α · log N · ef · d
```

where c₁, c₂ are constants.

#### Analyzing Zone Selection Cost

The first term grows linearly with Z:
```
T_zone = c₁ · Z · d
```

For Z too large, this dominates. For N = 10⁶, d = 128, c₁ ≈ 1:
- Z = 1000: T_zone ≈ 128K operations
- Z = 10000: T_zone ≈ 1.28M operations ✗

#### Analyzing Graph Quality

Zone-aware partitioning improves graph navigability, but benefits saturate.

**Intuition**: 
- Z too small → zones are large, spatial locality benefit lost
- Z too large → each zone contains few vectors, no connectivity benefit

**Optimal Balance**: Z = Θ(√N) ensures:
1. **Zone size**: |Zⱼ| ≈ N/Z = N/√N = √N vectors per zone
2. **Sufficient density**: √N vectors provide adequate graph connectivity
3. **Manageable overhead**: Zone selection scans √N centroids (sublinear)

#### Memory Overhead Analysis

From Corollary 5.1:
```
ΔS/S_HNSW = O(Z · d / (N · (d + M)))
```

For Z = √N:
```
ΔS/S_HNSW = O(√N · d / (N · (d + M)))
           = O(1/√N)
           → 0 as N → ∞
```

For Z = N (extreme over-partitioning):
```
ΔS/S_HNSW = O(N · d / (N · (d + M)))
           = O(d/(d + M))
           ≈ 89% overhead ✗
```

#### Build Time Analysis

K-Means clustering time:
```
T_cluster = O(K_iter · N · Z · d)
```

For Mini-Batch K-Means with batch size b:
```
T_cluster = O(K_iter · b · Z · d)
```

For constant K_iter and b:
```
T_cluster = O(Z · d)
```

This is negligible compared to HNSW construction O(N log N · M · d) when Z = O(√N).

#### Empirical Validation

Experiments on N = 10⁴ vectors:

| Z | Latency (ms) | Recall@10 | Memory (MB) | Build Time (s) |
|---|--------------|-----------|-------------|----------------|
| 25 (≈√N/2) | 0.049 | 63.2% | 17.7 | 0.41 |
| 50 | 0.051 | 64.0% | 17.8 | 0.43 |
| **100 (≈√N)** | **0.053** | **64.3%** | **17.9** | **0.45** |
| 200 (≈2√N) | 0.058 | 64.5% | 18.1 | 0.49 |
| 400 (≈4√N) | 0.071 | 64.6% | 18.5 | 0.58 |

Observations:
- Z < √N: Suboptimal latency, lower recall
- Z ≈ √N: **Optimal balance** ✓
- Z > √N: Increasing overhead, diminishing returns

∎

### Corollary 7.1: Practical Zone Count Selection

**Statement**: For practical deployment:

```
Z ∈ [√N/2, 2√N]
```

with Z = √N as the default recommendation.

**Justification**:
- Provides 50-400% flexibility around optimal point
- Accommodates variations in data distribution
- Simple formula: easy to compute and explain

---

## 8. Comparative Analysis

### 8.1 ZGQ vs Pure HNSW

| Metric | HNSW | ZGQ | Advantage |
|--------|------|-----|-----------|
| **Space** | O(N·M·d) | O(N·M·d + √N·d) | Asymptotically equal |
| **Query Time** | O(log N·ef·d) | O(√N·d + α log N·ef·d) | **ZGQ** (α < 1) |
| **Build Time** | O(N log N·M·d) | O(N^1.5·d + N log N·M·d) | HNSW (faster build) |
| **Recall@10** | ~65% | ~64% | Comparable |

**Key Insight**: Zone-aware construction reduces graph path length (α ≈ 0.74), yielding 35% faster queries with negligible memory overhead.

### 8.2 ZGQ vs IVF-Based Methods

#### Complexity Comparison

| Metric | IVF | IVF-PQ | ZGQ |
|--------|-----|--------|-----|
| **Space** | O(N·d) | O(N·b)* | O(N·M·d) |
| **Query** | O(Z·d + N/Z·n_probe·d) | O(Z·d + N/Z·n_probe·b) | O(√N·d + log N·d) |
| **Recall@10** | ~38% | ~19% | ~55% |

*where b ≪ d is PQ bytes per vector

#### Query Time Analysis

For target recall, IVF requires:
```
n_probe = Θ(r · Z / k)
```

Query cost:
```
T_IVF = O(Z · d + (N · r / k) · d)
```

For r = k (all true neighbors):
```
T_IVF = O(Z · d + N · d)
```

ZGQ query cost:
```
T_ZGQ = O(√N · d + log N · d)
```

**Speedup Factor**:
```
T_IVF / T_ZGQ ≈ N / log N
```

For N = 10⁴: Speedup ≈ 10000/13 ≈ **769×** (theoretical)

**Empirical Validation (High Recall Regime >90%)**:

Retired. An earlier version of this section reported a latency speedup of more than ten times over IVF-PQ at more than 90% recall. That run is not reproducible, and in the canonical benchmark (`v8/results/2026-11-08/`) IVF-PQ never reaches 90% recall (maximum 64.4%, 61.5% and 56.2% at 10K, 100K and 1M), so the ratio cannot be computed. See `v8/docs/BENCHMARKS.md` and `v8/docs/CLAIMS.md`.

**Note**: Any practical speedup over the theoretical figure would be reduced by:
1. IVF uses fewer probes (n_probe = 10, not full scan)
2. ZGQ has zone selection overhead
3. Cache effects and implementation optimizations

### 8.3 Memory-Recall Trade-off Analysis

**Pareto Efficiency**:

Define efficiency score:
```
η = Recall / (Memory · Latency)
```

Normalized scores (N = 10K):

| Algorithm | Recall | Memory (MB) | Latency (ms) | η (normalized) |
|-----------|--------|-------------|--------------|----------------|
| **ZGQ** | 55.1% | 17.9 | 0.058 | **1.00** ✓ |
| HNSW | 54.7% | 10.9 | 0.071 | 0.71 |
| IVF | 37.6% | 4.93 | 0.840 | 0.09 |
| IVF-PQ | 19.0% | 5.21 | 7.410 | 0.005 |

**Trade-off Visualization**:
As shown in the *Memory vs. Latency Trade-off* analysis:
- **ZGQ** (Blue): ~50MB Memory, ~11ms Latency
- **HNSW** (Purple): ~60MB Memory, ~15ms Latency

ZGQ achieves the best Pareto efficiency, balancing all three metrics optimally, providing lower latency with comparable or better memory footprint in high-performance configurations.

---

## 9. Empirical Validation

### 9.1 Experimental Setup

**Hardware**:
- CPU: Intel Core i5-12500H (12 cores, 2.5-4.5 GHz)
- RAM: 32 GB DDR4
- Storage: 512 GB NVMe SSD
- OS: Ubuntu 24.04 LTS (WSL2)

**Software**:
- Python 3.12.0
- hnswlib 0.8.0
- scikit-learn 1.3.0
- NumPy 1.26.0
- Numba 0.58.0 (JIT compilation)

**Datasets**:
- Synthetic vectors: randomly generated, L2-normalized
- Dimensions: d = 128
- Scales: N ∈ {10⁴, 10⁵, 10⁶}
- Query set: 100 queries per test

**Parameters**:
- ZGQ: Z = 100, M = 16, ef_construction = 200, ef_search = 50
- HNSW: M = 16, ef_construction = 200, ef_search = 50
- IVF: n_list = 100, n_probe = 10
- IVF-PQ: n_list = 100, n_probe = 10, m = 16 subspaces, 8 bits/subspace

### 9.2 Main Results

#### Table 1: Performance on 10K Vectors

| Algorithm | Latency (ms) | QPS | Recall@10 | Memory (MB) | Build (s) |
|-----------|--------------|-----|-----------|-------------|-----------|
| HNSW | 0.071 | 14,085 | 64.6% | 10.9 | 0.251 |
| **ZGQ** | **0.053** | **18,868** | 64.3% | 17.9 | 0.454 |
| IVF | 0.840 | 1,190 | 37.6% | 4.93 | 0.235 |
| IVF-PQ | 7.410 | 135 | 19.0% | 5.21 | 3.749 |

**Key Findings**:
- ZGQ: **1.34× faster** than HNSW (0.053 vs 0.071 ms)
- ZGQ: **15.8× faster** than IVF (0.053 vs 0.840 ms)
- ZGQ: **1.7× better recall** than IVF (64.3% vs 37.6%)

#### Table 2: Scalability Analysis

| N | Algorithm | Latency (ms) | Recall@10 | Memory (MB) | Overhead |
|---|-----------|--------------|-----------|-------------|----------|
| 10⁴ | HNSW | 0.071 | 64.6% | 10.9 | — |
| | ZGQ | 0.053 | 64.3% | 17.9 | +64% |
| 10⁵ | HNSW | 0.080 | 65.2% | 61.0 | — |
| | ZGQ | 0.060 | 64.8% | 61.5 | **+0.8%** |
| 10⁶ | HNSW | 0.120 | 66.1% | 610 | — |
| | ZGQ | 0.090 | 65.7% | 614 | **+0.7%** |

**Key Findings**:
- **Consistent speedup**: 1.33-1.35× across all scales
- **Vanishing overhead**: 64% → 0.8% → 0.7% (confirms O(1/√N) theory)
- **Stable recall**: <1% difference across all scales

### 9.3 Ablation Study: Zone Count Impact

| Z | Latency (ms) | Recall@10 | Memory (MB) | Relation to √N |
|---|--------------|-----------|-------------|----------------|
| 25 | 0.049 | 63.2% | 17.7 | √N/2 |
| 50 | 0.051 | 64.0% | 17.8 | √N/√2 |
| **100** | **0.053** | **64.3%** | **17.9** | **√N** ✓ |
| 200 | 0.058 | 64.5% | 18.1 | 2√N |
| 400 | 0.071 | 64.6% | 18.5 | 4√N |

**Validation**: Z = √N = √10000 = 100 provides optimal balance (confirms Theorem 7.1).

### 9.4 Path Reduction Factor Measurement

**Method**: Instrument HNSW search to count actual hops during queries.

**Results** (N = 10⁴, 100 queries):

| Algorithm | Avg Hops | Std Dev | Min | Max |
|-----------|----------|---------|-----|-----|
| Pure HNSW | 13.2 | 2.1 | 9 | 18 |
| ZGQ | 9.8 | 1.7 | 7 | 14 |

**Path Reduction**:
```
α = 9.8 / 13.2 = 0.742 ≈ 0.74
```

**Speedup Prediction**:
```
Predicted: 1/α = 1/0.74 = 1.35×
Measured: 0.071/0.053 = 1.34×
```

**Validation**: Empirical speedup matches theoretical prediction ✓

### 9.5 Build Time Amortization

**Setup**: N = 10⁶ vectors

| Metric | HNSW | ZGQ | Difference |
|--------|------|-----|------------|
| Build Time | 45.3 s | 82.1 s | +36.8 s |
| Query Latency | 0.120 ms | 0.090 ms | -0.030 ms |

**Break-even Calculation**:
```
Queries to amortize = 36,800 ms / 0.030 ms = 1,226,667 queries
```

At 1000 QPS: Break-even in **20.4 minutes**

At 10000 QPS: Break-even in **2.0 minutes**

**Conclusion**: Build time overhead is negligible for production systems serving millions of queries.

---

## 10. Conclusion

### 10.1 Summary of Theoretical Contributions

This document has provided rigorous mathematical proofs establishing:

1. **Space Efficiency (Theorem 5.1)**:
   - ZGQ achieves O(N·M·d) space complexity
   - Overhead O(√N·d) → 0 as N → ∞
   - <1% memory cost at N ≥ 10⁵

2. **Query Optimization (Theorem 6.1)**:
   - Zone-aware construction reduces path length: α ≈ 0.74
   - Query time: O(√N·d + α log N·d)
   - 1.35× speedup over pure HNSW

3. **Optimal Parameterization (Theorem 7.1)**:
   - Z* = Θ(√N) minimizes query latency
   - Balances zone selection cost with graph quality
   - Maintains vanishing memory overhead

4. **Comparative Advantages**:
   - **vs HNSW**: 35% faster with same asymptotic memory
   - **vs IVF**: 15× faster with 1.7× better recall
   - **vs IVF-PQ**: 140× faster with 3× better recall

### 10.2 Validation of Research Hypothesis

**Original Hypothesis**: By organizing data spatially before constructing a unified HNSW graph, we create an inherently better-structured topology.

**Validation Status**: **CONFIRMED** ✓

**Evidence**:
1. Mathematical proofs demonstrate O(1/√N) overhead
2. Path reduction factor α = 0.74 measured empirically
3. Consistent 1.35× speedup across 10K-1M scale
4. Theory and experiments align precisely

### 10.3 Practical Implications

**When to Use ZGQ**:
- ✓ Medium-to-large datasets (N ≥ 10⁵)
- ✓ Latency-critical applications (<1 ms target)
- ✓ High recall requirements (≥60%)
- ✓ Reasonable memory budgets

**When to Avoid ZGQ**:
- ✗ Tiny datasets (N < 10⁴) → use pure HNSW
- ✗ Extreme memory constraints → use IVF-PQ
- ✗ Rapidly changing data → use simpler indices

### 10.4 Contributions to ANNS Research

1. **Architectural Innovation**: First unified zone-aware graph construction
2. **Rigorous Theory**: Complete complexity analysis with proofs
3. **Empirical Validation**: Extensive experiments confirming theory
4. **Practical Framework**: Ready-to-deploy implementation

### 10.5 Future Research Directions

1. **Adaptive Zone Selection**: Learn query-dependent zone weights
2. **Hierarchical Zoning**: Multi-level partitions for billion-scale
3. **GPU Acceleration**: Parallelize zone selection and search
4. **Dynamic Updates**: Efficient incremental zone management
5. **Compression Integration**: Combine ZGQ with Product Quantization
6. **Theoretical Tightening**: Worst-case bounds on recall guarantees

---

## References

Based on research draft and empirical findings from:
- Nathan Aldyth Prananta Ginting, Jordan Chay Ming Hong, Jaeden Ting YiYong
- Faculty of Engineering and Technology, Sunway University
- Implementation: https://github.com/nathangtg/dbms-research

### Key Literature

1. Malkov, Y. A., & Yashunin, D. A. (2020). "Efficient and robust approximate nearest neighbor search using hierarchical navigable small world graphs." IEEE TPAMI, 42(4), 824-836.

2. Wang, M., Xu, X., Yue, Q., & Wang, Y. (2021). "A comprehensive survey and experimental comparison of graph-based approximate nearest neighbor search." PVLDB, 14(11), 1964-1978.

3. Chen, Q., et al. (2021). "SPANN: Highly-efficient billion-scale approximate nearest neighbor search." NeurIPS 34, 5199-5212.

4. Akhil, A., & Sivashankar, G. (2025). "Zonal HNSW: Scalable approximate nearest neighbor search for billion-scale datasets." ICSSAS 2025.

5. Additional 16 references from literature review (see draft.md)

---

## Appendix A: Mathematical Notation Reference

| Symbol | Meaning |
|--------|---------|
| N | Number of vectors in dataset |
| d | Dimension of vectors |
| Z | Number of zones/clusters |
| M | Average degree in HNSW graph |
| k | Number of nearest neighbors to return |
| ef | HNSW exploration factor |
| n_probe | Number of zones to search |
| α | Path reduction factor (≈0.74) |
| φ(x) | Zone assignment function |
| cⱼ | Centroid of zone j |
| eⱼ | Entry point of zone j |
| D | Dataset {x₁, ..., xₙ} |
| G | HNSW graph |
| I | ZGQ index (G, φ, C, E) |

---

## Appendix B: Implementation Pseudocode

### B.1 K-Means Clustering
```python
def kmeans_clustering(data, n_clusters, max_iter=100):
    """
    Partition data into n_clusters zones
    
    Input: data (N × d), n_clusters (Z)
    Output: labels (N,), centroids (Z × d)
    """
    # Initialize centroids randomly
    centroids = random_sample(data, n_clusters)
    
    for iteration in range(max_iter):
        # Assignment step
        distances = cdist(data, centroids)  # N × Z
        labels = argmin(distances, axis=1)  # N
        
        # Update step
        for j in range(n_clusters):
            mask = (labels == j)
            if sum(mask) > 0:
                centroids[j] = mean(data[mask], axis=0)
        
        # Check convergence
        if not changed(labels):
            break
    
    return labels, centroids
```

### B.2 Entry Point Computation
```python
def compute_entry_points(data, labels, centroids):
    """
    Find nearest vector to each centroid
    
    Input: data (N × d), labels (N,), centroids (Z × d)
    Output: entry_points (Z,)
    """
    Z = len(centroids)
    entry_points = zeros(Z, dtype=int)
    
    for j in range(Z):
        # Get vectors in zone j
        zone_mask = (labels == j)
        zone_data = data[zone_mask]
        zone_indices = where(zone_mask)[0]
        
        # Find closest to centroid
        distances = norm(zone_data - centroids[j], axis=1)
        local_idx = argmin(distances)
        entry_points[j] = zone_indices[local_idx]
    
    return entry_points
```

### B.3 Zone-Sorted HNSW Construction
```python
def build_zgq_index(data, labels, centroids, entry_points, M=16):
    """
    Build unified HNSW with zone-aware ordering
    
    Input: data (N × d), labels (N,), M (degree)
    Output: hnsw_index
    """
    # Sort data by zone
    sort_idx = argsort(labels)
    sorted_data = data[sort_idx]
    
    # Build HNSW graph
    hnsw = hnswlib.Index(space='l2', dim=data.shape[1])
    hnsw.init_index(max_elements=len(data), M=M, ef_construction=200)
    
    # Add vectors in zone-sorted order
    hnsw.add_items(sorted_data, sort_idx)
    
    return hnsw, sort_idx
```

### B.4 ZGQ Search
```python
def zgq_search(query, hnsw, labels, centroids, k=10, n_probe=1):
    """
    Perform zone-aware k-NN search
    
    Input: query (d,), index components, k, n_probe
    Output: indices (k,), distances (k,)
    """
    if n_probe == 1:
        # Fast path: direct HNSW search
        indices, distances = hnsw.knn_query(query, k)
        return indices[0], distances[0]
    
    else:
        # Multi-zone path
        # 1. Select nearest zones
        zone_dists = norm(centroids - query, axis=1)
        nearest_zones = argsort(zone_dists)[:n_probe]
        
        # 2. Extended HNSW search
        k_prime = min(k * n_probe, len(labels))
        indices, distances = hnsw.knn_query(query, k_prime)
        indices, distances = indices[0], distances[0]
        
        # 3. Filter to selected zones
        mask = isin(labels[indices], nearest_zones)
        filtered_idx = indices[mask][:k]
        filtered_dist = distances[mask][:k]
        
        return filtered_idx, filtered_dist
```

---

## Appendix C: Execution & Reproducibility

### C.1 ZGQ Execution Model

The ZGQ implementation (available in `v8/zgq`) simplifies the execution pipeline compared to traditional IVF-PQ workflows.

**Directory Structure**:
```
v8/
├── zgq/               # Core implementation
│   ├── index.py       # Main ZGQIndex class
│   ├── search.py      # Search logic
│   └── core/          # Components (zones, graph, quantization)
└── benchmarks/        # Reproducibility scripts
```

**Execution Simplicity**:
Unlike IVF-PQ which requires manual tuning of `n_list`, `n_probe`, `m`, and `nbits`, ZGQ offers an auto-configuration mode:

```python
from zgq import ZGQIndex

# ZGQ: Auto-configuration
index = ZGQIndex(n_zones='auto') 
index.build(vectors)
```

### C.2 Comparison with IVF-PQ Workflow

| Feature | ZGQ Workflow | IVF-PQ Workflow |
|---------|--------------|-----------------|
| **Configuration** | `n_zones='auto'` | Requires `n_list`, `n_probe`, `m`, `nbits` tuning |
| **Training** | Integrated single-pass build | Separate training (clustering) + encoding steps |
| **Search** | Unified graph traversal | Multi-stage: Coarse quantizer -> PQ scan -> Re-ranking |
| **Complexity** | Low (Black-box ready) | High (Requires expert tuning) |

### C.3 Reproducing Results

To reproduce the ZGQ results:

1. Navigate to the `v8` directory.
2. Install dependencies: `pip install -r requirements.txt`
3. Run the benchmark suite:
   ```bash
   python -m benchmarks.run_benchmarks --dataset 10k
   ```

**Note on IVF-PQ Comparison**:
The IVF-PQ results presented in Section 8.2 were obtained using the standard FAISS implementation with `n_list=100`, `n_probe=10`, `m=16`, and `nbits=8`. The ZGQ execution model (shown above) is significantly simpler as it abstracts these parameters into the `n_zones='auto'` configuration.

---

**Document Version**: 1.0  
**Last Updated**: October 20, 2025  
**Status**: FINAL - Ready for Review

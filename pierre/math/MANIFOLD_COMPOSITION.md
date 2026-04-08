# Manifold Composition Theory: Connecting Grassmannian, SLERP, and Dual Quaternion Blending

## STATUS: ARCHIVED (2026-04-08)

**Adversarial Review V2 verdict:** The experimental program tested the core proposals:
- **SLERP (Section 2): KILLED.** Finding #382/#383 — LERP wins on all 5 domains. Candy wrapper is implicit regularization, not a defect.
- **Polar Decomposition (Section 3): UNTESTED.** Theoretical only. SLERP kill suggests diminishing returns.
- **PBD (Section 4): KILLED.** Finding #391 — unnecessary given sub-linear interference (α=0.38).
- **Symplectic (Section 5): THEORETICALLY UNSOUND.** No Hamiltonian, no phase space, no smooth ODE. Promotion is a discrete sequence of unrelated perturbations, not a continuous trajectory.

**What remains valid:** The Grassmannian analysis (Section 1) and the Pythagorean promotion bound (sqrt(K) compounding) are mathematically correct. The game dev analogies inspired useful experiments but are metaphors, not theorems.

**This document is preserved for intellectual history. Do not cite it as current theory.**

---

## Original Content (preserved below)

## Why This Document Was Written

Pierre composes adapters via linear combination: `h = W·x + Σ αᵢ Bᵢ(Aᵢ·x)`.
Grassmannian A guarantees ε₁ = 0 (parameter-space interference).
But ε₂ > 0 (activation-space interference) because linear blending of B-matrices
does not respect the geometry of the weight manifold.

Game engines solved this 20 years ago for skeletal animation.
This document formalized the connection and proposed fixes. The experiments showed
that the problem (candy wrapper / activation interference) is either beneficial
(implicit regularization) or already handled by routing.

---

## 1. The Geometry of Adapter Composition

### 1.1 Where Adapters Live

A LoRA adapter Δᵢ = BᵢAᵢ is a rank-r matrix in R^{d_out × d_in}.
The set of all rank-r matrices is a smooth manifold M_r ⊂ R^{d_out × d_in}.

The A-matrix Aᵢ ∈ R^{d_in × r} defines an r-dimensional subspace of R^{d_in}.
The set of all such subspaces is the Grassmannian Gr(r, d_in).

The B-matrix Bᵢ ∈ R^{r × d_out} maps FROM the subspace TO the output space.
Given a fixed Aᵢ (our Grassmannian slot), Bᵢ lives on the Stiefel-like manifold
of linear maps from a fixed r-dim subspace to R^{d_out}.

### 1.2 The Problem with Linear Blending

Current composition:
```
Δ_composed = Σᵢ αᵢ BᵢAᵢ
```

This is a linear combination in matrix space. But rank-r matrices do NOT form
a linear subspace — the sum of two rank-r matrices can have rank up to 2r.

Concretely: if B₁(A₁·x) points "north" and B₂(A₂·x) points "south",
their weighted sum can be near zero (destructive interference).
This is the **candy wrapper effect** of skeletal animation.

### 1.3 The Game Engine Fix: Composition on the Manifold

Instead of averaging in matrix space, average on the manifold.
Three approaches, from simplest to most principled:

---

## 2. SLERP Composition (Spherical Linear Interpolation)

### 2.1 Definition

For two unit vectors u, v on S^{n-1}, SLERP is:
```
SLERP(u, v, t) = sin((1-t)θ)/sin(θ) · u + sin(tθ)/sin(θ) · v
```
where θ = arccos(u·v).

Unlike LERP `(1-t)u + tv`, SLERP stays on the sphere (preserves norm)
and traverses the geodesic (shortest path on the manifold).

### 2.2 Application to B-matrices

Normalize B-matrices to unit Frobenius norm:
```
B̂ᵢ = Bᵢ / ||Bᵢ||_F
sᵢ = ||Bᵢ||_F  (scale)
```

For two adapters:
```
B̂_composed = SLERP(B̂₁, B̂₂, α₂/(α₁+α₂))
s_composed = α₁·s₁ + α₂·s₂  (scales blend linearly)
B_composed = s_composed · B̂_composed
```

For N adapters: use iterative SLERP (sequential pairwise, Nesterov-style).
Or use the Karcher mean on the sphere (converges in 3-5 iterations).

### 2.3 Why This Helps

Linear blend of B̂₁ and B̂₂ has norm ≤ 1 (equality only if B̂₁ = B̂₂).
SLERP blend has norm = 1 always.

The "candy wrapper" is exactly this norm collapse: linear blending reduces
the effective magnitude of the composed adapter when B-matrices are diverse.
SLERP prevents it.

### 2.4 Theorem: SLERP Preserves Adapter Strength

**Theorem.** For B̂₁, B̂₂ on the unit sphere with angle θ between them:
```
||SLERP(B̂₁, B̂₂, t)||_F = 1  for all t ∈ [0,1]
||LERP(B̂₁, B̂₂, t)||_F = √(1 - 2t(1-t)(1-cosθ))  ≤ 1
```

The LERP norm dip is maximized at t=0.5: `||LERP||² = (1 + cosθ)/2`.
For our measured B-matrix cos = 0.29 at N=5: `||LERP||_0.5 = √(1.29/2) = 0.80`.
That is a 20% strength reduction from linear blending. SLERP eliminates it.

### 2.5 Cost

SLERP for rank-4 B-matrices: O(r × d_out) per pair = O(4 × d_model).
For N adapters: O(N × r × d_out) total. Comparable to current linear blend.

---

## 3. Polar Decomposition Blending (Dual Quaternion Analog)

### 3.1 The Full Fix

SLERP handles directions but not the full matrix structure.
The proper generalization is the **polar decomposition**:

For each adapter delta Δᵢ = BᵢAᵢ:
```
Δᵢ = Rᵢ · Sᵢ    (polar decomposition)
```
where Rᵢ is orthogonal (rotation) and Sᵢ is symmetric positive semi-definite (stretch).

Compose by:
1. Blend rotations via SLERP: R_composed = SLERP(R₁, R₂, ..., Rₙ; α₁,...,αₙ)
2. Blend stretches linearly: S_composed = Σᵢ αᵢ Sᵢ
3. Recompose: Δ_composed = R_composed · S_composed

### 3.2 Why This Is Correct

In game animation, this decomposition is exactly Dual Quaternion Blending (DQB).
Kavan et al. (2006) proved:

**Theorem (Kavan).** DQB preserves rigid body volume. Specifically, for
transformations Mᵢ = Rᵢ + εtᵢ in dual quaternion form:
```
det(DQB(M₁,...,Mₙ; α)) = 1  (volume-preserving)
det(LBS(M₁,...,Mₙ; α)) ≤ 1  (volume-collapsing)
```

The adapter analog: "volume" = the effective rank of the composed perturbation.
Linear blending can reduce effective rank (destructive interference).
Polar decomposition blending preserves it.

### 3.3 For Rank-4 LoRA

The polar decomposition of a rank-r matrix involves:
1. Compute SVD: Δᵢ = Uᵢ Σᵢ Vᵢ^T
2. R = Uᵢ Vᵢ^T (orthogonal part)
3. S = Vᵢ Σᵢ Vᵢ^T (symmetric part)

For rank=4, this is a 4×4 SVD — cost O(r³) = O(64). Negligible.

### 3.4 Theorem: Polar Blend Bounds Activation Interference

**Theorem.** Let Δ₁ = R₁S₁ and Δ₂ = R₂S₂ be polar decompositions. Then:
```
||Δ₁·x + Δ₂·x||² = ||R₁S₁x + R₂S₂x||²
                   = ||S₁x||² + ||S₂x||² + 2(S₁x)^T R₁^T R₂ (S₂x)
```

The cross term depends on R₁^T R₂ (relative rotation).
Under SLERP blending, this rotation is parameterized smoothly.
Under linear blending, R₁+R₂ can be degenerate (the candy wrapper).

**Bound:** For SLERP-blended composition:
```
|cos(Δ₁x, Δ₂x)| ≤ |cos_R(R₁, R₂)| · (||S₁x|| · ||S₂x||) / (||Δ₁x|| · ||Δ₂x||)
```

where cos_R is the rotation angle between R₁ and R₂.
With Grassmannian A (orthogonal read-spaces), the S terms are independent,
so the bound tightens to:
```
E[|cos(Δ₁x, Δ₂x)|] ≤ cos_R / 1 = cos_R
```

This means: **activation interference is bounded by the rotation angle between
adapter directions, NOT by the B-matrix alignment.** The Grassmannian A structure
ensures the stretch components don't amplify interference.

---

## 4. Position-Based Dynamics for Runtime Correction

### 4.1 Formulation

After computing the naive composed output h_composed, apply constraint projections:

**Constraint C₁: Norm preservation.**
```
||h_composed - h_base||₂ ≈ E[||Δᵢ·x||₂]  (composed effect ≈ single-adapter effect)
```
Projection: rescale h_composed to target norm.

**Constraint C₂: Cross-adapter decorrelation.**
```
|⟨Bᵢ(Aᵢ·x), Bⱼ(Aⱼ·x)⟩| < τ  for all i≠j
```
Projection: Gram-Schmidt on the adapter activations (cost: O(N² · d_out)).

**Constraint C₃: Base preservation.**
```
||h_composed||₂ / ||h_base||₂ ∈ [1-δ, 1+δ]
```
Projection: clamp the ratio.

### 4.2 PBD Iteration

```python
def pbd_correct(h_base, adapter_activations, alphas, max_iter=2):
    """Position-Based Dynamics correction for adapter composition."""
    h = h_base + sum(a * act for a, act in zip(alphas, adapter_activations))

    for _ in range(max_iter):
        # C1: Normalize composed perturbation
        delta = h - h_base
        target_norm = mean(norm(act) for act in adapter_activations)
        if norm(delta) > 0:
            delta = delta * (target_norm / norm(delta))

        # C2: Decorrelate adapter activations (adjust alphas)
        # Use Gram-Schmidt to orthogonalize the top-N activations
        ortho_acts = gram_schmidt(adapter_activations)
        h = h_base + sum(a * act for a, act in zip(alphas, ortho_acts))

        # C3: Preserve base model scale
        ratio = norm(h) / norm(h_base)
        if ratio > 1 + delta_threshold:
            h = h_base + (h - h_base) * ((1 + delta_threshold) / ratio)

    return h
```

### 4.3 Convergence

PBD converges in 1-4 iterations for well-conditioned constraints (Müller et al. 2007).
Cost per iteration: O(N · d_out) for Gram-Schmidt + O(d_out) for normalization.
Total: O(N · d_out · max_iter) ≈ O(N · d_model · 2).

For N=5, d_model=1024: ~10K operations per token. Negligible vs attention (~1M ops).

---

## 5. Symplectic Promotion

### 5.1 The Promotion Dynamical System

Each promotion step:
```
W_{k+1} = W_k + α · Δ_k
```

This is Euler integration of the "ODE": dW/dk = α · Δ(W).
Euler integration does NOT preserve the Hamiltonian H(W) = model_quality(W).

### 5.2 Leapfrog (Störmer-Verlet) Promotion

Instead of one-shot promotion:
```
# Half-step: evaluate adapter on current base
Δ_{k+½} = generate_adapter(W_k, domain_k)

# Full-step: promote
W_{k+1} = W_k + α · Δ_{k+½}

# Half-step: re-evaluate adapter on promoted base, adjust
Δ_{k+1} = generate_adapter(W_{k+1}, domain_k)
correction = (Δ_{k+1} - Δ_{k+½}) / 2
W_{k+1} = W_{k+1} + α · correction
```

### 5.3 Energy Conservation Bound

**Theorem (Symplectic Integration).** For a Störmer-Verlet integrator with step h:
```
|H(W_k) - H(W_0)| ≤ C · h²  for all k
```

vs Euler:
```
|H(W_k) - H(W_0)| ≤ C · k · h
```

The symplectic version has BOUNDED error (doesn't grow with k).
The Euler version has GROWING error (linear in number of promotion cycles).

For promotion cycles: h = α · ||Δ||_F / ||W||_F (relative perturbation per step).
At scale=5, rank=4, ||B||≈0.38: h ≈ 0.06 per step.

Symplectic bound: error ≤ C · 0.06² = C · 0.0036 (constant for all K).
Euler bound: error ≤ C · K · 0.06 (grows linearly with K).

After K=5 cycles: symplectic error 0.0036 vs Euler error 0.30.
**83x better stability for multi-cycle promotion.**

### 5.4 Cost

One extra adapter generation per promotion cycle (the "half-step correction").
Since adapter generation via M2P is ~10ms, this adds ~10ms per promotion.
Promotions happen offline (not at inference), so this is negligible.

---

## 6. Summary: The Three-Layer Fix

```
Layer 1: Grassmannian A (PROVEN)
  → ε₁ = 0 (parameter-space interference eliminated)
  → √K promotion compounding (Pythagorean theorem)
  → Welch capacity bound (N_max = d/r)

Layer 2: Manifold B Composition (NEW — from game dev)
  → SLERP/polar blend: preserves adapter strength (no candy wrapper)
  → PBD correction: runtime guarantee for activation orthogonality
  → Cost: O(N · d_model) per token (negligible vs attention)

Layer 3: Symplectic Promotion (NEW — from physics sim)
  → Energy-preserving multi-cycle promotion
  → Error bounded by O(h²) independent of K (vs O(K·h) for naive)
  → Cost: one extra M2P call per promotion cycle (~10ms)
```

Together, these three layers address ALL six epsilons:
- ε₁: Grassmannian (proven zero)
- ε₂: Manifold composition (SLERP/polar bound)
- ε₃: M2P quality (d_M2P ≥ d_int, SHINE recipe)
- ε₄: Symplectic promotion (O(h²) not O(K·h))
- ε₅: Routing (TF-IDF 95%, with Q_wrong measurement pending)
- ε₆: Scale (derivable from ||B|| and d_model)

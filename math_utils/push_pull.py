"""
Gaussian Distribution Transport on Associated Bundle
====================================================

Push-forward and pull-back operations for multivariate Gaussians via
parallel transport operators Ω_ij.

Mathematical Framework:
----------------------
**Associated Bundle Structure:**
    - Principal bundle: (C, SO(3))
    - Statistical fiber: F = {N(μ, Σ) : μ ∈ ℝᴷ, Σ ∈ Sym⁺⁺(K)}
    - Agent sections: q(c) = N(μ_q(c), Σ_q(c))

**Push-Forward Operation:**
Given Gaussian q_j(c) = N(μ_j, Σ_j) and transport Ω_ij(c):

    Ω_ij[q_j](c) = N(Ω_ij μ_j, Ω_ij Σ_j Ω_ijᵀ)

**Properties:**
    1. Linear transport: μ' = Ω μ
    2. Covariance transport: Σ' = Ω Σ Ωᵀ (preserves SPD)
    3. Precision transport: Λ' = Ω Λ Ωᵀ (same form!)

**Usage in Alignment:**
    KL(q_i || Ω_ij[q_j]) measures how well i's belief matches
    the transported belief from j.

Numerical Efficiency:
--------------------
- Precompute Σ⁻¹ when needed multiple times
- Use Ω orthogonality: Ω⁻¹ = Ωᵀ (cheap!)
- Cache pushed distributions within optimization step

Author: Chris & Christine
Date: November 2025
"""
# ===========================================================================
# SECTION 1: Add at TOP of file (after existing imports)
# ===========================================================================

import numpy as np
from typing import Tuple, Optional
from dataclasses import dataclass
from math_utils.numerical_utils import safe_inv

# ===========================================================================
# GPU/CUDA BACKEND INTEGRATION
# ===========================================================================

try:
    from math_utils.cuda_kernels import (
        transport_gaussian_cupy,
        transport_gaussian_batch_cupy,
        kl_transported_cupy,
        is_cupy_available,
    )
    _CUDA_KERNELS_AVAILABLE = is_cupy_available()
except ImportError:
    _CUDA_KERNELS_AVAILABLE = False

# NEW: Import Numba-accelerated versions
try:
    from math_utils.numba_kernels import (
        push_gaussian_numba,
        compute_kl_transported_numba
    )
    _NUMBA_AVAILABLE = True
except ImportError:
    _NUMBA_AVAILABLE = False


# =============================================================================
# Container for Transported Gaussians
# =============================================================================

@dataclass(frozen=True)
class GaussianDistribution:
    """
    Immutable Gaussian distribution N(μ, Σ).
    
    Attributes:
        mu: Mean vector, shape (*S, K)
        Sigma: Covariance matrix, shape (*S, K, K)
        Sigma_inv: Precision matrix (optional), shape (*S, K, K)
    
    Properties:
        - All arrays are float32 for memory efficiency
        - Sigma guaranteed SPD (checked on construction)
        - Immutable after creation
    """
    mu: np.ndarray
    Sigma: np.ndarray
    Sigma_inv: Optional[np.ndarray] = None
    
    def __post_init__(self):
        """Validate and convert types."""
        # Convert to float32
        object.__setattr__(self, 'mu', np.asarray(self.mu, dtype=np.float32, order='C'))
        object.__setattr__(self, 'Sigma', np.asarray(self.Sigma, dtype=np.float32, order='C'))
        
        if self.Sigma_inv is not None:
            object.__setattr__(self, 'Sigma_inv', 
                             np.asarray(self.Sigma_inv, dtype=np.float32, order='C'))
        
        # Validate shapes
        K = self.mu.shape[-1]
        if self.Sigma.shape[-2:] != (K, K):
            raise ValueError(f"Shape mismatch: mu has K={K}, Sigma shape {self.Sigma.shape}")
        
        if self.Sigma_inv is not None and self.Sigma_inv.shape != self.Sigma.shape:
            raise ValueError(f"Sigma_inv shape mismatch")
 
    
    @property
    def K(self) -> int:
        """Latent dimension."""
        return int(self.mu.shape[-1])
    
    @property
    def spatial_shape(self) -> Tuple[int, ...]:
        """Spatial dimensions (*S)."""
        return self.mu.shape[:-1]


# =============================================================================
# Push-Forward (Transport) Operation
# =============================================================================

def push_gaussian(
    gaussian: GaussianDistribution,
    Omega: np.ndarray,
    *,
    compute_precision: bool = False,
    eps: float = 1e-8,
) -> GaussianDistribution:
    """
    Push Gaussian forward via transport operator Ω.
    
    Transformation:
        N(μ, Σ) → N(Ω μ, Ω Σ Ωᵀ)
    
    Precision matrix transforms the same way:
        Λ = Σ⁻¹ → Λ' = Ω Λ Ωᵀ
    
    Args:
        gaussian: Source distribution
        Omega: Transport operator, shape (*S, K, K)
        compute_precision: If True, compute Σ'⁻¹
        eps: Regularization for numerical stability
    
    Returns:
        pushed: Transported distribution
    
    Properties:
        - Preserves Gaussianity
        - Σ' remains SPD (Ω orthogonal)
        - If Σ⁻¹ provided, computes (Σ')⁻¹ efficiently
    
    Examples:
        >>> # Create source distribution
        >>> mu = np.array([1.0, 0.0, 0.0])
        >>> Sigma = np.eye(3)
        >>> q = GaussianDistribution(mu, Sigma)
        >>> 
        >>> # Transport operator (90° rotation about z)
        >>> angle = np.pi / 2
        >>> Omega = np.array([
        ...     [np.cos(angle), -np.sin(angle), 0],
        ...     [np.sin(angle),  np.cos(angle), 0],
        ...     [0, 0, 1]
        ... ])
        >>> 
        >>> # Push forward
        >>> q_pushed = push_gaussian(q, Omega)
        >>> q_pushed.mu  # Should be rotated
        array([0., 1., 0.])
    
    Notes:
        - Uses float64 internally for precision
        - Returns float32 for memory efficiency
        - Symmetrizes Σ' to remove numerical asymmetry
    """
    
    # ========================================================================
    # NEW: FAST PATH for simple scalar case (3-5x faster)
    # ========================================================================
    if (_NUMBA_AVAILABLE and 
        not compute_precision and 
        gaussian.mu.ndim == 1 and 
        Omega.ndim == 2):
        
        # Convert to float64 for Numba
        mu = np.asarray(gaussian.mu, dtype=np.float64)
        Sigma = np.asarray(gaussian.Sigma, dtype=np.float64)
        Omega_f64 = np.asarray(Omega, dtype=np.float64)
        
        # Ultra-fast Numba kernel
        mu_pushed, Sigma_pushed = push_gaussian_numba(mu, Sigma, Omega_f64)
        
        # Return as float32
        return GaussianDistribution(
            mu_pushed.astype(np.float32),
            Sigma_pushed.astype(np.float32),
            None
        )
    
    
    mu = np.asarray(gaussian.mu, dtype=np.float64)
    Sigma = np.asarray(gaussian.Sigma, dtype=np.float64)
    Omega = np.asarray(Omega, dtype=np.float64)
    
    # Validate shapes
    K = mu.shape[-1]
    if Omega.shape[-2:] != (K, K):
        raise ValueError(f"Omega shape {Omega.shape} incompatible with K={K}")
    
    
    
    
    
    # ========== Push mean: μ' = Ω μ ==========
    mu_pushed = np.einsum('...ij,...j->...i', Omega, mu, optimize=True)
    
    # ========== Push covariance: Σ' = Ω Σ Ωᵀ ==========
    # Step 1: Ω Σ
    tmp = np.einsum('...ik,...kl->...il', Omega, Sigma, optimize=True)
    
    # Step 2: (Ω Σ) Ωᵀ
    Sigma_pushed = np.einsum('...ij,...kj->...ik', tmp, Omega, optimize=True)
    
    # Symmetrize (remove numerical asymmetry)
    Sigma_pushed = 0.5 * (Sigma_pushed + np.swapaxes(Sigma_pushed, -1, -2))
    
    # Add tiny regularization for numerical stability
    MIN_VARIANCE = 1e-4  # Absolute floor on variance
    reg = MIN_VARIANCE * np.eye(K, dtype=np.float64)
    Sigma_pushed = Sigma_pushed + reg
    
    # ========== Compute precision if requested ==========
    Sigma_inv_pushed = None
    
    if compute_precision or gaussian.Sigma_inv is not None:
        if gaussian.Sigma_inv is not None:
            # For precision matrix: Λ' = (Σ')⁻¹ = (Ω Σ Ωᵀ)⁻¹
            # Since Ω orthogonal: Λ' = Ω Λ Ωᵀ (same form as covariance!)
            Sigma_inv = np.asarray(gaussian.Sigma_inv, dtype=np.float64)
            
            # Check if Ω is orthogonal (sample first element if batch)
            Omega_to_check = Omega if Omega.ndim == 2 else Omega.reshape(-1, K, K)[0]
            is_ortho = _is_orthogonal(Omega_to_check, tol=1e-4)
            
            if is_ortho:
                # Fast path: Λ' = Ω Λ Ωᵀ
                # Step 1: Ω Λ
                tmp_inv = np.einsum('...ik,...kl->...il', Omega, Sigma_inv, optimize=True)
                # Step 2: (Ω Λ) Ωᵀ
                Sigma_inv_pushed = np.einsum('...ij,...kj->...ik', tmp_inv, Omega, optimize=True)
            else:
                # Fallback: same formula (works for any invertible Ω)
                Sigma_inv_pushed = _push_precision_via_solve(Omega, Sigma_inv)
        
        else:
            # Compute from pushed covariance
            Sigma_inv_pushed = safe_inv(Sigma_pushed, eps=eps)
        
        # Symmetrize
        if Sigma_inv_pushed is not None:
            Sigma_inv_pushed = 0.5 * (Sigma_inv_pushed + np.swapaxes(Sigma_inv_pushed, -1, -2))
    
    # ========== Cast to float32 and return ==========
    mu_out = mu_pushed.astype(np.float32, copy=False)
    Sigma_out = Sigma_pushed.astype(np.float32, copy=False)
    Sigma_inv_out = Sigma_inv_pushed.astype(np.float32, copy=False) if Sigma_inv_pushed is not None else None
    
    return GaussianDistribution(mu_out, Sigma_out, Sigma_inv_out)








def _is_orthogonal(M: np.ndarray, tol: float = 1e-4) -> bool:
    """Check if matrix is orthogonal: Mᵀ M ≈ I."""
    K = M.shape[0]
    deviation = np.linalg.norm(M.T @ M - np.eye(K), ord='fro') / K
    return deviation < tol






def _push_precision_via_solve(Omega: np.ndarray, Sigma_inv: np.ndarray) -> np.ndarray:
    """
    Compute pushed precision: Λ' = Ω⁻ᵀ Λ Ω⁻¹.

    For orthogonal Ω (Ω⁻¹ = Ωᵀ), this reduces to Ω Λ Ωᵀ.
    For non-orthogonal Ω (GL(K)), must use the correct inverse formula.

    The pushed covariance is Σ' = Ω Σ Ωᵀ, so the pushed precision is:
        Λ' = (Σ')⁻¹ = (Ω Σ Ωᵀ)⁻¹ = Ω⁻ᵀ Σ⁻¹ Ω⁻¹ = Ω⁻ᵀ Λ Ω⁻¹

    Args:
        Omega: Transport operator, shape (..., K, K)
        Sigma_inv: Precision matrix Λ, shape (..., K, K)

    Returns:
        Sigma_inv_pushed: Λ' = Ω⁻ᵀ Λ Ω⁻¹, shape (..., K, K)
    """
    # Check if Omega is orthogonal (fast path)
    K = Omega.shape[-1]
    # Use a single representative for batch check
    flat = Omega.reshape(-1, K, K)
    sample = flat[0]
    if _is_orthogonal(sample):
        # Orthogonal: Ω⁻¹ = Ωᵀ, so Ω⁻ᵀ Λ Ω⁻¹ = Ω Λ Ωᵀ
        tmp = np.einsum('...ik,...kl->...il', Omega, Sigma_inv, optimize=True)
        out = np.einsum('...ij,...kj->...ik', tmp, Omega, optimize=True)
    else:
        # Non-orthogonal: compute Ω⁻¹ explicitly
        Omega_inv = np.linalg.inv(Omega)
        # Ω⁻ᵀ = (Ω⁻¹)ᵀ
        Omega_inv_T = np.swapaxes(Omega_inv, -2, -1)
        # Λ' = Ω⁻ᵀ Λ Ω⁻¹
        tmp = np.einsum('...ik,...kl->...il', Omega_inv_T, Sigma_inv, optimize=True)
        out = np.einsum('...ij,...jk->...ik', tmp, Omega_inv, optimize=True)

    return out



# =============================================================================
# Pull-Back Operation (Inverse Transport)
# =============================================================================

def pull_gaussian(
    gaussian: GaussianDistribution,
    Omega: np.ndarray,
    *,
    compute_precision: bool = False,
    eps: float = 1e-8,
) -> GaussianDistribution:
    """
    Pull Gaussian back via inverse transport Ω⁻¹.

    Transformation:
        N(μ, Σ) → N(Ω⁻¹ μ, Ω⁻¹ Σ Ω⁻ᵀ)

    Args:
        gaussian: Pushed distribution
        Omega: Transport operator (will be inverted)
        compute_precision: If True, compute Σ'⁻¹
        eps: Regularization

    Returns:
        pulled: Original (source) distribution

    Notes:
        - Inverse of push_gaussian
        - For GL(K): Uses actual matrix inverse (not transpose)
        - Used rarely (typically only push forward)
    """
    # Invert transport: use actual inverse for GL(K) compatibility
    # NOTE: For orthogonal Ω, this equals Ωᵀ, but we use inv() for generality
    batch_shape = Omega.shape[:-2]
    K = Omega.shape[-1]
    Omega_flat = Omega.reshape(-1, K, K)
    Omega_inv_flat = np.linalg.inv(Omega_flat)
    Omega_inv = Omega_inv_flat.reshape(batch_shape + (K, K))

    # Pull is push with inverted operator
    return push_gaussian(gaussian, Omega_inv, compute_precision=compute_precision, eps=eps)


# =============================================================================
# Batch Operations
# =============================================================================

def push_gaussian_batch(
    gaussians: list,
    Omegas: list,
    *,
    compute_precision: bool = False,
    eps: float = 1e-8,
) -> list:
    """
    Push multiple Gaussians with corresponding transports.
    
    Args:
        gaussians: List of GaussianDistribution
        Omegas: List of transport operators (same length)
        compute_precision: If True, compute precisions
        eps: Regularization
    
    Returns:
        pushed: List of pushed distributions
    
    Examples:
        >>> # Push multiple spatial locations
        >>> mu_batch = np.random.randn(10, 3)
        >>> Sigma_batch = np.tile(np.eye(3), (10, 1, 1))
        >>> gaussians = [GaussianDistribution(mu_batch[i], Sigma_batch[i]) 
        ...              for i in range(10)]
        >>> 
        >>> # Random rotations
        >>> Omegas = [random_rotation(3) for _ in range(10)]
        >>> 
        >>> pushed = push_gaussian_batch(gaussians, Omegas)
    """
    if len(gaussians) != len(Omegas):
        raise ValueError(f"Length mismatch: {len(gaussians)} gaussians, {len(Omegas)} Omegas")
    
    return [
        push_gaussian(g, Om, compute_precision=compute_precision, eps=eps)
        for g, Om in zip(gaussians, Omegas)
    ]


# =============================================================================
# Utilities
# =============================================================================

def compute_kl_transported(
    gaussian_i: GaussianDistribution,
    gaussian_j: GaussianDistribution,
    Omega_ij: np.ndarray,
    *,
    eps: float = 1e-8,
) -> np.ndarray:
    """
    Compute KL(q_i || Ω_ij[q_j]) efficiently.
    
    This is the alignment energy term used in free energy minimization.
    
    Args:
        gaussian_i: Receiver distribution
        gaussian_j: Sender distribution
        Omega_ij: Transport operator i←j
        eps: Regularization
    
    Returns:
        KL: Shape (*S,), alignment divergence
    
    Notes:
        - Uses kl_gaussian from kl_divergence.py
        - Automatically pushes gaussian_j via Omega_ij
    
    Examples:
        >>> from kl_divergence import kl_gaussian
        >>> # Receiver
        >>> mu_i = np.array([1.0, 0.0, 0.0])
        >>> Sigma_i = np.eye(3)
        >>> q_i = GaussianDistribution(mu_i, Sigma_i)
        >>> 
        >>> # Sender
        >>> mu_j = np.array([0.0, 1.0, 0.0])
        >>> Sigma_j = np.eye(3)
        >>> q_j = GaussianDistribution(mu_j, Sigma_j)
        >>> 
        >>> # Transport (identity for testing)
        >>> Omega = np.eye(3)
        >>> 
        >>> # Alignment KL
        >>> kl = compute_kl_transported(q_i, q_j, Omega)
        >>> kl.shape
        ()
    """
    
    # ========================================================================
    # NEW: ULTRA-FAST PATH (10x faster - combines transport + KL)
    # ========================================================================
    if (_NUMBA_AVAILABLE and 
        gaussian_i.mu.ndim == 1 and 
        gaussian_j.mu.ndim == 1 and
        Omega_ij.ndim == 2):
        
        # Convert to float64 for Numba
        mu_i = np.asarray(gaussian_i.mu, dtype=np.float64)
        Sigma_i = np.asarray(gaussian_i.Sigma, dtype=np.float64)
        mu_j = np.asarray(gaussian_j.mu, dtype=np.float64)
        Sigma_j = np.asarray(gaussian_j.Sigma, dtype=np.float64)
        Omega = np.asarray(Omega_ij, dtype=np.float64)
        
        # Single Numba kernel does transport + KL
        kl = compute_kl_transported_numba(mu_i, Sigma_i, mu_j, Sigma_j, Omega)
        
        return np.float32(kl)
    
    
    # Import here to avoid circular dependency
    from math_utils.numerical_utils import kl_gaussian
    
    
    
    
    # Push j → i
    q_j_transported = push_gaussian(gaussian_j, Omega_ij, eps=eps)
    
    # Compute KL(i || transported_j)
    kl = kl_gaussian(
        gaussian_i.mu,
        gaussian_i.Sigma,
        q_j_transported.mu,
        q_j_transported.Sigma,
        eps=eps,
    )
    
    return kl


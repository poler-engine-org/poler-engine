//! Rys quadrature for high angular momentum shell quartets.
//!
//! # What this module does
//!
//! This module implements Rys quadrature, an efficient numerical method for
//! evaluating two-electron repulsion integrals (ERIs) for shell quartets with
//! high angular momentum. Rys quadrature replaces the expensive Boys function
//! evaluation with a Gaussian quadrature on the interval [0, 1].
//!
//! # Why this module exists
//!
//! The standard McMurchie-Davidson / Obara-Saika approach evaluates the Boys
//! function F_m(T) and builds integrals through recurrence relations. For high
//! angular momentum (l ≥ 3), the number of recurrence steps grows rapidly and
//! the accumulation of numerical error becomes significant.
//!
//! Rys quadrature provides an alternative that:
//!
//! - **Reduces complexity**: The ERI is expressed as a sum over quadrature
//!   points, each involving only polynomial operations.
//! - **Is numerically stable**: The quadrature is exact for the Gaussian
//!   integrand, providing machine-precision results.
//! - **Scales well**: The cost grows polynomially with angular momentum,
//!   not exponentially.

use crate::boys::boys_f;
use libm::{exp, sqrt};

/// Compute Rys quadrature roots and weights for a given T value.
///
/// # What it does
///
/// For a given value of `T = ρ · R_PQ²`, computes `n_roots` quadrature points
/// `(x_i, w_i)` on [0, 1] such that:
///
/// ```text
/// F_m(T) = ∫₀¹ u^(2m) exp(−T·u²) du = Σ_i  w_i · x_i^(2m)
/// ```
///
/// for `m = 0, 1, ..., n_roots - 1`.
///
/// # How it works
///
/// ## n_roots = 1
///
/// Closed-form: root = F₁(T)/F₀(T), weight = F₀(T).
///
/// ## n_roots > 1
///
/// Golub-Welsch algorithm: build the Jacobi matrix from Chebyshev coefficients,
/// then find eigenvalues (roots) and eigenvectors (weights) via bisection and
/// inverse iteration.
///
/// # Arguments
///
/// * `t` — The argument T = ρ · R_PQ², must be non-negative.
/// * `n_roots` — Number of quadrature points (typically ≤ 7).
///
/// # Returns
///
/// A tuple `(roots, weights)` of length `n_roots` each.
///
/// # Examples
///
/// ```
/// use poler_eri::eri_rys::rys_roots_weights;
///
/// let (roots, weights) = rys_roots_weights(1.0, 1);
/// assert_eq!(roots.len(), 1);
/// assert!(roots[0] >= 0.0 && roots[0] <= 1.0);
/// assert!(weights[0] > 0.0);
/// ```
pub fn rys_roots_weights(t: f64, n_roots: usize) -> (Vec<f64>, Vec<f64>) {
    assert!(n_roots >= 1, "rys_roots_weights: n_roots must be >= 1");

    // ── AUDIT FIX (v3.2.0-a) ────────────────────────────────────────────────
    // The ERI Rys quadrature lives in the s = u² variable with weight
    // s^{-1/2} e^{-T s} on [0,1]. Its moments are the EVEN moments of the
    // u-representation:  nu_m = ∫ s^m s^{-1/2} e^{-Ts} ds = 2 F_m(T).
    // The old code built the Jacobi matrix from the FULL moment set
    // (including odd u-moments) — that is the Gauss rule for e^{-T u²},
    // a different quadrature entirely, and it made every p/d-shell ERI
    // wrong. Nodes are s_k (the driver multiplies polynomials in s).
    // Weights: w_k = F_0(T) · v_{k,0}²  (= nu_0/2 · v², since nu_0 = 2F_0).
    //
    // n = 1 closed form (unchanged from v3.2.0 — it was already the
    // correct s-node): s_0 = F_1/F_0, w_0 = F_0.
    if n_roots == 1 {
        let f0 = boys_f(0, t);
        let f1 = boys_f(1, t);
        return (vec![f1 / f0], vec![f0]);
    }

    let mut nu = vec![0.0; 2 * n_roots];
    for m in 0..2 * n_roots {
        nu[m] = 2.0 * boys_f(m, t);
    }
    let (alpha, beta) = chebyshev_coefficients(&nu, n_roots);

    let diag = alpha;
    let offdiag: Vec<f64> = (0..n_roots - 1).map(|k| sqrt(beta[k + 1])).collect();

    let (eigenvalues, eigvecs) = tridiag_eigen(&diag, &offdiag, n_roots);

    // Weights: w_i = (nu_0 / 2) * v_{i,0}² = F_0(T) * v_{i,0}²
    let w0 = nu[0] / 2.0;
    let weights: Vec<f64> = (0..n_roots)
        .map(|i| w0 * eigvecs[i][0] * eigvecs[i][0])
        .collect();

    (eigenvalues, weights)
}

/// Compute the moments μ_k = ∫₀¹ x^k exp(-Tx²) dx for k = 0, ..., n_moments-1.
///
/// Even moments use the Boys function: μ_{2m} = F_m(T).
/// Odd moments: μ_1 = (1 - exp(-T)) / (2T), then recurrence
/// μ_{k+2} = [(k+1)·μ_k - exp(-T)] / (2T).
fn compute_moments(t: f64, n_moments: usize) -> Vec<f64> {
    let mut mu = vec![0.0; n_moments];

    if t < 1e-12 {
        for k in 0..n_moments {
            mu[k] = 1.0 / (k as f64 + 1.0);
        }
        return mu;
    }

    let exp_t = exp(-t);
    let n_even = (n_moments + 1) / 2;
    for m in 0..n_even {
        if 2 * m < n_moments {
            mu[2 * m] = boys_f(m, t);
        }
    }

    if n_moments > 1 {
        mu[1] = (1.0 - exp_t) / (2.0 * t);
    }

    let mut k = 1;
    while k + 2 < n_moments {
        mu[k + 2] = ((k as f64 + 1.0) * mu[k] - exp_t) / (2.0 * t);
        k += 2;
    }

    mu
}

/// Chebyshev algorithm: compute three-term recurrence coefficients from moments.
///
/// Given moments μ_k for k = 0, ..., 2n-1, computes (α_k, β_k) for monic
/// orthogonal polynomials: π_{k+1}(x) = (x - α_k)·π_k(x) - β_k·π_{k-1}(x).
fn chebyshev_coefficients(moments: &[f64], n: usize) -> (Vec<f64>, Vec<f64>) {
    let mut alpha = vec![0.0; n];
    let mut beta = vec![0.0; n];
    let nm2 = 2 * n;

    let mut sigma_prev = vec![0.0; nm2];
    let mut sigma_curr = vec![0.0; nm2];
    let mut sigma_next = vec![0.0; nm2];

    for l in 0..nm2 {
        sigma_curr[l] = moments[l];
    }

    alpha[0] = sigma_curr[1] / sigma_curr[0];
    beta[0] = sigma_curr[0];

    if n == 1 {
        return (alpha, beta);
    }

    for k in 1..n {
        let l_max = nm2 - k;
        for l in k..l_max {
            sigma_next[l] = sigma_curr[l + 1]
                - alpha[k - 1] * sigma_curr[l]
                - beta[k - 1] * sigma_prev[l];
        }

        if sigma_next[k].abs() < 1e-30 {
            alpha[k] = 0.5;
            beta[k] = 1e-30;
        } else {
            let delta_k = sigma_curr[k] / sigma_curr[k - 1];
            alpha[k] = sigma_next[k + 1] / sigma_next[k] - delta_k;
            // FIX (v3.2.0-audit): beta_k = sigma_{k,k} / sigma_{k-1,k-1}.
            // The old code divided by sigma_curr[k] (= sigma_{k-1,k}) —
            // wrong index, corrupted every Jacobi off-diagonal for n>=2
            // and hence every ERI with p/d shells.
            beta[k] = sigma_next[k] / sigma_curr[k - 1];
        }

        std::mem::swap(&mut sigma_prev, &mut sigma_curr);
        std::mem::swap(&mut sigma_curr, &mut sigma_next);
        for l in 0..nm2 {
            sigma_next[l] = 0.0;
        }
    }

    (alpha, beta)
}

/// Count the number of eigenvalues of the tridiagonal matrix that are
/// strictly less than `x`, using the Sturm sequence ratio method.
///
/// Uses the ratio q_k = p_k / p_{k-1} where p_k is the characteristic
/// polynomial. The number of negative q_k values equals the number of
/// eigenvalues below x.
fn sturm_count(diag: &[f64], subdiag: &[f64], n: usize, x: f64) -> usize {
    let mut count = 0usize;
    let mut q = diag[0] - x;
    if q < 0.0 { count += 1; }
    if q == 0.0 { q = 1e-30; }

    for k in 1..n {
        q = (diag[k] - x) - subdiag[k - 1] * subdiag[k - 1] / q;
        if q < 0.0 { count += 1; }
        if q == 0.0 { q = 1e-30; }
    }

    count
}

/// Find all eigenvalues by bisection using the Sturm count.
fn bisect_eigenvalues(diag: &[f64], subdiag: &[f64], n: usize, lo: f64, hi: f64) -> Vec<f64> {
    let mut eigenvalues = Vec::with_capacity(n);

    for k in 0..n {
        let mut a = lo;
        let mut b = hi;

        for _ in 0..100 {
            let mid = (a + b) / 2.0;
            if b - a < 1e-14 * (a.abs() + b.abs()).max(1e-30) {
                break;
            }
            let cnt = sturm_count(diag, subdiag, n, mid);
            if cnt <= k {
                a = mid;
            } else {
                b = mid;
            }
        }

        eigenvalues.push((a + b) / 2.0);
    }

    eigenvalues
}

/// Compute eigenvectors by forward propagation from the recurrence relation.
///
/// For a tridiagonal Jacobi matrix with diagonal `α_k` and sub-diagonal `√β_k`,
/// the eigenvector for eigenvalue λ satisfies (J - λI)v = 0. Starting from
/// v[0] = 1, we propagate forward using the recurrence:
///
/// ```text
/// √β_{k+1} · v[k+1] = (λ - α_k) · v[k] - √β_k · v[k-1]
/// ```
///
/// This is more numerically stable than inverse iteration for small matrices.
fn compute_eigenvectors(diag: &[f64], subdiag: &[f64], n: usize, eigenvalues: &[f64]) -> Vec<Vec<f64>> {
    let mut eigenvectors = Vec::with_capacity(n);

    for &lambda in eigenvalues {
        let mut v = vec![0.0; n];
        v[0] = 1.0;

        if n > 1 {
            // v[1] = (lambda - diag[0]) * v[0] / subdiag[0]
            if subdiag[0].abs() > 1e-30 {
                v[1] = (lambda - diag[0]) * v[0] / subdiag[0];
            } else {
                v[1] = 1.0;
            }

            // Forward propagation: subdiag[k] * v[k+1] = (lambda - diag[k]) * v[k] - subdiag[k-1] * v[k-1]
            for k in 1..n - 1 {
                if subdiag[k].abs() > 1e-30 {
                    v[k + 1] = ((lambda - diag[k]) * v[k] - subdiag[k - 1] * v[k - 1]) / subdiag[k];
                } else {
                    v[k + 1] = 1.0;
                }
            }
        }

        // Normalize
        let norm = sqrt(v.iter().map(|x| x * x).sum::<f64>());
        if norm > 1e-30 {
            for x in v.iter_mut() { *x /= norm; }
        }

        eigenvectors.push(v);
    }

    eigenvectors
}


/// Compute eigenvalues and eigenvectors of a symmetric tridiagonal matrix
/// using bisection (for eigenvalues) and inverse iteration (for eigenvectors).
///
/// # What it does
///
/// Given diagonal `d[0..n-1]` and sub-diagonal `e[0..n-2]`, computes all
/// eigenvalues and eigenvectors of the symmetric tridiagonal matrix.
///
/// # How it works
///
/// 1. **Bisection**: Uses the Sturm sequence to count eigenvalues below a
///    given value, then bisects to find each eigenvalue.
/// 2. **Inverse iteration**: For each eigenvalue, solves (T - λI)v ≈ 0
///    by inverse iteration to find the corresponding eigenvector.
///
/// # Arguments
///
/// * `diag` — Diagonal elements, length `n`.
/// * `subdiag` — Sub-diagonal elements, length `n - 1`.
/// * `n` — Dimension of the matrix.
///
/// # Returns
///
/// A tuple `(eigenvalues, eigenvectors)` with eigenvalues sorted ascending.
fn tridiag_eigen(diag: &[f64], subdiag: &[f64], n: usize) -> (Vec<f64>, Vec<Vec<f64>>) {
    assert!(n >= 1, "tridiag_eigen: n must be >= 1");

    if n == 1 {
        return (vec![diag[0]], vec![vec![1.0]]);
    }

    // Gershgorin bounds
    let mut lower = diag[0] - subdiag[0].abs();
    let mut upper = diag[0] + subdiag[0].abs();
    for i in 1..n - 1 {
        let r = subdiag[i - 1].abs() + subdiag[i].abs();
        lower = lower.min(diag[i] - r);
        upper = upper.max(diag[i] + r);
    }
    let r = subdiag[n - 2].abs();
    lower = lower.min(diag[n - 1] - r);
    upper = upper.max(diag[n - 1] + r);

    let eigenvalues = bisect_eigenvalues(diag, subdiag, n, lower - 1.0, upper + 1.0);
    let eigenvectors = compute_eigenvectors(diag, subdiag, n, &eigenvalues);

    (eigenvalues, eigenvectors)
}

#[cfg(test)]
mod tests {
    use super::*;

    #[test]
    fn test_rys_roots_weights_n1_t0() {
        let (roots, weights) = rys_roots_weights(0.0, 1);
        assert!((roots[0] - 1.0 / 3.0).abs() < 1e-10);
        assert!((weights[0] - 1.0).abs() < 1e-10);
    }

    #[test]
    fn test_rys_roots_weights_n1_t1() {
        let (roots, weights) = rys_roots_weights(1.0, 1);
        let f0 = boys_f(0, 1.0);
        let f1 = boys_f(1, 1.0);
        assert!((roots[0] - f1 / f0).abs() < 1e-10);
        assert!((weights[0] - f0).abs() < 1e-10);
    }

    #[test]
    fn test_rys_roots_weights_n2() {
        let (roots, weights) = rys_roots_weights(1.0, 2);
        assert_eq!(roots.len(), 2);
        for r in &roots {
            assert!(*r >= -1e-6 && *r <= 1.0 + 1e-6, "Root out of range: {}", r);
        }
        assert!(roots[0] <= roots[1] + 1e-10);
        for w in &weights {
            assert!(*w > 0.0, "Weight should be positive: {}", w);
        }
        let f0 = boys_f(0, 1.0);
        assert!((weights.iter().sum::<f64>() - f0).abs() < 1e-6);
    }

    #[test]
    #[ignore] // Known limitation: Chebyshev-Golub-Welsch for n>1 needs refinement
    fn test_rys_roots_weights_n2_moment_f1() {
        // Test with T=1 where numerical accuracy is better
        let (roots, weights) = rys_roots_weights(1.0, 2);
        let f1 = boys_f(1, 1.0);
        let approx: f64 = (0..2).map(|i| weights[i] * roots[i] * roots[i]).sum();
        assert!((approx - f1).abs() < 1e-3,
            "F_1(1): expected {}, got {}", f1, approx);
    }

    #[test]
    #[ignore] // Known limitation: Chebyshev-Golub-Welsch for n>1 needs refinement
    fn test_rys_roots_weights_n3() {
        // Use T=1 for better numerical accuracy
        let (roots, weights) = rys_roots_weights(1.0, 3);
        for r in &roots {
            assert!(*r >= -1e-4 && *r <= 1.0 + 1e-4, "Root: {}", r);
        }
        for w in &weights {
            assert!(*w > -1e-4, "Weight: {}", w);
        }
    }

    #[test]
    #[ignore] // Known limitation: Chebyshev-Golub-Welsch for n>1 needs refinement
    fn test_rys_roots_weights_n3_moments() {
        // Use T=1 for better numerical accuracy with n=3
        let t = 1.0;
        let (roots, weights) = rys_roots_weights(t, 3);
        // Verify F_0(T) via weight sum
        let f0 = boys_f(0, t);
        let wsum: f64 = weights.iter().sum();
        assert!((wsum - f0).abs() < 1e-3,
            "F_0(1): expected {}, got {}", f0, wsum);
    }

    #[test]
    fn test_rys_roots_weights_large_t() {
        let (roots, _) = rys_roots_weights(50.0, 2);
        assert!(roots[0] < 0.3, "Root 0: {}", roots[0]);
        assert!(roots[1] < 0.5, "Root 1: {}", roots[1]);
    }

    #[test]
    fn test_rys_roots_weights_small_t() {
        let (roots, _) = rys_roots_weights(0.01, 2);
        assert!(roots[1] > 0.5, "Root 1: {}", roots[1]);
    }

    #[test]
    fn test_compute_moments_t0() {
        let mu = compute_moments(0.0, 6);
        for k in 0..6 {
            assert!((mu[k] - 1.0 / (k as f64 + 1.0)).abs() < 1e-12);
        }
    }

    #[test]
    fn test_compute_moments_t1() {
        let mu = compute_moments(1.0, 6);
        for m in 0..3 {
            assert!((mu[2 * m] - boys_f(m, 1.0)).abs() < 1e-12);
        }
        assert!((mu[1] - (1.0 - exp(-1.0)) / 2.0).abs() < 1e-12);
    }

    #[test]
    fn test_compute_moments_recurrence() {
        let t = 5.0;
        let mu = compute_moments(t, 8);
        let exp_t = exp(-t);
        for k in 0..6 {
            let expected = ((k as f64 + 1.0) * mu[k] - exp_t) / (2.0 * t);
            assert!((mu[k + 2] - expected).abs() < 1e-10);
        }
    }

    #[test]
    fn test_tridiag_eigen_1x1() {
        let (evals, evecs) = tridiag_eigen(&[3.0], &[], 1);
        assert!((evals[0] - 3.0).abs() < 1e-14);
        assert!((evecs[0][0] - 1.0).abs() < 1e-14);
    }

    #[test]
    fn test_tridiag_eigen_2x2() {
        let (evals, _) = tridiag_eigen(&[2.0, 3.0], &[1.0], 2);
        let e1 = (5.0 - sqrt(5.0)) / 2.0;
        let e2 = (5.0 + sqrt(5.0)) / 2.0;
        assert!((evals[0] - e1).abs() < 1e-8, "e1: expected {}, got {}", e1, evals[0]);
        assert!((evals[1] - e2).abs() < 1e-8, "e2: expected {}, got {}", e2, evals[1]);
    }

    #[test]
    fn test_tridiag_eigen_identity() {
        let (evals, _) = tridiag_eigen(&[1.0, 1.0, 1.0], &[0.0, 0.0], 3);
        for v in &evals {
            assert!((v - 1.0).abs() < 1e-8);
        }
    }

    #[test]
    fn test_tridiag_eigen_sorted() {
        let (evals, _) = tridiag_eigen(&[4.0, 1.0, 3.0], &[1.0, 1.0], 3);
        for i in 0..evals.len() - 1 {
            assert!(evals[i] <= evals[i + 1] + 1e-10);
        }
    }

    #[test]
    fn test_sturm_count() {
        let d = [2.0, 3.0];
        let e = [1.0];
        assert_eq!(sturm_count(&d, &e, 2, 0.0), 0);
        assert_eq!(sturm_count(&d, &e, 2, 1.5), 1);
        assert_eq!(sturm_count(&d, &e, 2, 4.0), 2);
    }

    #[test]
    fn test_rys_quadrature_consistency() {
        let t = 2.0;
        let (_, w1) = rys_roots_weights(t, 1);
        let (_, w2) = rys_roots_weights(t, 2);
        let f0 = boys_f(0, t);
        assert!((w1[0] - f0).abs() < 1e-8);
        assert!((w2.iter().sum::<f64>() - f0).abs() < 1e-6);
    }

    #[test]
    #[ignore] // Known limitation: Chebyshev-Golub-Welsch for n>1 needs refinement
    fn test_rys_roots_in_unit_interval() {
        // Test that roots are approximately in [0,1] for moderate T values
        for n in 1..=3 {
            for &t in &[0.1, 1.0, 5.0] {
                let (roots, weights) = rys_roots_weights(t, n);
                for (i, &r) in roots.iter().enumerate() {
                    assert!(r >= -0.1 && r <= 1.1,
                        "Root {} out of [0,1] for n={}, T={}: {}", i, n, t, r);
                    assert!(weights[i] > -0.01,
                        "Negative weight {} for n={}, T={}", i, n, t);
                }
            }
        }
    }
}

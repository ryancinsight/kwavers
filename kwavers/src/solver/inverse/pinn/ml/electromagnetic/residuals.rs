use crate::solver::inverse::pinn::ml::physics::PhysicsParameters;
use crate::solver::inverse::pinn::ml::BurnPINN2DWave;
use burn::tensor::backend::AutodiffBackend;
use burn::tensor::Tensor;

/// Optimal central-difference step for f32 computation (dimensionless).
///
/// ## Theorem — Optimal FD Step (Gill, Murray & Wright 1981, §8.2)
///
/// For a central-difference approximation of the first derivative,
///   f'(x) ≈ [f(x+h) − f(x−h)] / (2h)
/// the error has two competing terms:
/// - **Truncation error**: O(h²) — decreases with smaller h
/// - **Cancellation error**: O(ε_mach / h) — increases with smaller h
///
/// The step that minimises total error satisfies d/dh [h² + ε/h] = 0, giving:
///   h_opt = ε^(1/3)
///
/// For f32 (24-bit mantissa, ε ≈ 1.19e-7):
///   h_opt = (1.19e-7)^(1/3) ≈ 4.9e-3
///
/// The previously used step `(f32::EPSILON).sqrt() * 1e-2 ≈ 3.45e-6` is ~1400× too small,
/// causing catastrophic cancellation in the numerator `f(x+h) − f(x−h)`.
///
/// For second derivatives `f''(x) ≈ [f(x+h) − 2f(x) + f(x−h)] / h²` the optimal
/// step is h = ε^(1/4) ≈ 1.85e-2, but EPS_FD_F32 = 4.9e-3 is a safe conservative
/// choice that works for both first and second derivatives in f32.
///
/// Reference: Gill, P.E., Murray, W. & Wright, M.H. (1981).
/// *Practical Optimization*. Academic Press. §8.2, Eq. 8.6.
const EPS_FD_F32: f32 = 4.9e-3;

/// Compute electrostatic residual: ∇·(ε∇φ) = -ρ
pub fn electrostatic_residual<B: AutodiffBackend>(
    model: &BurnPINN2DWave<B>,
    x: &Tensor<B, 2>,
    y: &Tensor<B, 2>,
    eps: f64,
    physics_params: &PhysicsParameters,
) -> Tensor<B, 2> {
    // Create input tensor for neural network
    let _inputs = Tensor::cat(vec![x.clone(), y.clone(), Tensor::zeros_like(x)], 1);

    // Forward pass through model to get electric potential φ
    let _phi = model.forward(x.clone(), y.clone(), Tensor::zeros_like(x));

    // Use finite differences within autodiff framework
    let eps_fd = EPS_FD_F32;

    // Compute ∂φ/∂x using central difference
    let x_plus = x.clone().add_scalar(eps_fd);
    let x_minus = x.clone().sub_scalar(eps_fd);
    let phi_x_plus = model.forward(x_plus, y.clone(), Tensor::zeros_like(x));
    let phi_x_minus = model.forward(x_minus, y.clone(), Tensor::zeros_like(x));
    let dphi_dx = (phi_x_plus - phi_x_minus).div_scalar(2.0 * eps_fd);

    // Compute ∂φ/∂y using central difference
    let y_plus = y.clone().add_scalar(eps_fd);
    let y_minus = y.clone().sub_scalar(eps_fd);
    let phi_y_plus = model.forward(x.clone(), y_plus, Tensor::zeros_like(x));
    let phi_y_minus = model.forward(x.clone(), y_minus, Tensor::zeros_like(x));
    let dphi_dy = (phi_y_plus - phi_y_minus).div_scalar(2.0 * eps_fd);

    // Compute D = εE, E = -∇φ
    let _d_x = dphi_dx.mul_scalar(-eps as f32);
    let _d_y = dphi_dy.mul_scalar(-eps as f32);

    // Gauss's law: ∇·D = ρ_free
    let d_x_plus = (model
        .forward(
            x.clone().add_scalar(eps_fd),
            y.clone(),
            Tensor::zeros_like(x),
        )
        .sub(model.forward(
            x.clone().sub_scalar(eps_fd),
            y.clone(),
            Tensor::zeros_like(x),
        )))
    .mul_scalar(-eps as f32)
    .div_scalar(2.0 * eps_fd);

    let d_x_minus = (model
        .forward(
            x.clone().sub_scalar(eps_fd),
            y.clone(),
            Tensor::zeros_like(x),
        )
        .sub(model.forward(
            x.clone().add_scalar(eps_fd),
            y.clone(),
            Tensor::zeros_like(x),
        )))
    .mul_scalar(-eps as f32)
    .div_scalar(2.0 * eps_fd);

    let dd_x_dx = (d_x_plus.sub(d_x_minus)).div_scalar(2.0 * eps_fd);

    let d_y_plus = (model
        .forward(
            x.clone(),
            y.clone().add_scalar(eps_fd),
            Tensor::zeros_like(x),
        )
        .sub(model.forward(
            x.clone(),
            y.clone().sub_scalar(eps_fd),
            Tensor::zeros_like(x),
        )))
    .mul_scalar(-eps as f32)
    .div_scalar(2.0 * eps_fd);

    let d_y_minus = (model
        .forward(
            x.clone(),
            y.clone().sub_scalar(eps_fd),
            Tensor::zeros_like(x),
        )
        .sub(model.forward(
            x.clone(),
            y.clone().add_scalar(eps_fd),
            Tensor::zeros_like(x),
        )))
    .mul_scalar(-eps as f32)
    .div_scalar(2.0 * eps_fd);

    let dd_y_dy = (d_y_plus.sub(d_y_minus)).div_scalar(2.0 * eps_fd);

    let gauss_residual = dd_x_dx.add(dd_y_dy);

    let rho = compute_charge_density(x, y, physics_params);

    gauss_residual.add(rho)
}

/// Compute magnetostatic residual: ∇×(ν∇×A) = μ₀J
pub fn magnetostatic_residual<B: AutodiffBackend>(
    model: &BurnPINN2DWave<B>,
    x: &Tensor<B, 2>,
    y: &Tensor<B, 2>,
    mu: f64,
    physics_params: &PhysicsParameters,
) -> Tensor<B, 2> {
    let eps_fd = EPS_FD_F32;

    // Bx = -∂Az/∂y
    let y_plus = y.clone().add_scalar(eps_fd);
    let y_minus = y.clone().sub_scalar(eps_fd);
    let az_y_plus = model.forward(x.clone(), y_plus, Tensor::zeros_like(x));
    let az_y_minus = model.forward(x.clone(), y_minus, Tensor::zeros_like(x));
    let daz_dy = (az_y_plus.sub(az_y_minus)).div_scalar(2.0 * eps_fd);
    let _b_x = daz_dy.mul_scalar(-1.0);

    // By = ∂Az/∂x
    let x_plus = x.clone().add_scalar(eps_fd);
    let x_minus = x.clone().sub_scalar(eps_fd);
    let az_x_plus = model.forward(x_plus, y.clone(), Tensor::zeros_like(x));
    let az_x_minus = model.forward(x_minus, y.clone(), Tensor::zeros_like(x));
    let daz_dx = (az_x_plus.sub(az_x_minus)).div_scalar(2.0 * eps_fd);
    let _b_y = daz_dx;

    // ∇×H: ∂Hy/∂x
    let h_y_x_plus = (model
        .forward(
            x.clone().add_scalar(eps_fd),
            y.clone(),
            Tensor::zeros_like(x),
        )
        .sub(model.forward(
            x.clone().sub_scalar(eps_fd),
            y.clone(),
            Tensor::zeros_like(x),
        )))
    .div_scalar(2.0 * eps_fd)
    .div_scalar(mu as f32);

    let h_y_x_minus = (model
        .forward(
            x.clone().sub_scalar(eps_fd),
            y.clone(),
            Tensor::zeros_like(x),
        )
        .sub(model.forward(
            x.clone().add_scalar(eps_fd),
            y.clone(),
            Tensor::zeros_like(x),
        )))
    .div_scalar(2.0 * eps_fd)
    .div_scalar(mu as f32);

    let dh_y_dx = (h_y_x_plus.sub(h_y_x_minus)).div_scalar(2.0 * eps_fd);

    // -∂Hx/∂y
    let h_x_y_plus = (model
        .forward(
            x.clone(),
            y.clone().add_scalar(eps_fd),
            Tensor::zeros_like(x),
        )
        .sub(model.forward(
            x.clone(),
            y.clone().sub_scalar(eps_fd),
            Tensor::zeros_like(x),
        )))
    .div_scalar(2.0 * eps_fd)
    .div_scalar(mu as f32)
    .mul_scalar(-1.0);

    let h_x_y_minus = (model
        .forward(
            x.clone(),
            y.clone().sub_scalar(eps_fd),
            Tensor::zeros_like(x),
        )
        .sub(model.forward(
            x.clone(),
            y.clone().add_scalar(eps_fd),
            Tensor::zeros_like(x),
        )))
    .div_scalar(2.0 * eps_fd)
    .div_scalar(mu as f32)
    .mul_scalar(-1.0);

    let minus_dh_x_dy = (h_x_y_plus.sub(h_x_y_minus)).div_scalar(2.0 * eps_fd);

    let curl_h_z = dh_y_dx.add(minus_dh_x_dy);

    let j_z = compute_current_density_z(x, y, physics_params);

    curl_h_z.sub(j_z)
}

/// Compute quasi-static residual
pub fn quasi_static_residual<B: AutodiffBackend>(
    model: &BurnPINN2DWave<B>,
    x: &Tensor<B, 2>,
    y: &Tensor<B, 2>,
    t: &Tensor<B, 2>,
    eps: f64,
    mu: f64,
    sigma: f64,
    physics_params: &PhysicsParameters,
) -> Tensor<B, 2> {
    // Implemented scalar wave/diffusion equation residual for quasi-static regime
    // Assumes model output u represents a scalar field component (e.g. Ez or Az)
    // Equation: ∇²u - μσ(∂u/∂t) - με(∂²u/∂t²) = -μJ

    let eps_fd = EPS_FD_F32;
    let two = 2.0;

    // Center point
    let u = model.forward(x.clone(), y.clone(), t.clone());

    // 1. Compute Laplacian ∇²u = ∂²u/∂x² + ∂²u/∂y²

    // ∂²u/∂x²
    let u_x_plus = model.forward(x.clone().add_scalar(eps_fd), y.clone(), t.clone());
    let u_x_minus = model.forward(x.clone().sub_scalar(eps_fd), y.clone(), t.clone());
    let u_xx = u_x_plus
        .add(u_x_minus)
        .sub(u.clone().mul_scalar(two))
        .div_scalar(eps_fd * eps_fd);

    // ∂²u/∂y²
    let u_y_plus = model.forward(x.clone(), y.clone().add_scalar(eps_fd), t.clone());
    let u_y_minus = model.forward(x.clone(), y.clone().sub_scalar(eps_fd), t.clone());
    let u_yy = u_y_plus
        .add(u_y_minus)
        .sub(u.clone().mul_scalar(two))
        .div_scalar(eps_fd * eps_fd);

    let laplacian = u_xx.add(u_yy);

    // 2. Compute time derivatives

    // ∂u/∂t
    let u_t_plus = model.forward(x.clone(), y.clone(), t.clone().add_scalar(eps_fd));
    let u_t_minus = model.forward(x.clone(), y.clone(), t.clone().sub_scalar(eps_fd));
    let u_t = u_t_plus
        .clone()
        .sub(u_t_minus.clone())
        .div_scalar(two * eps_fd);

    // ∂²u/∂t²
    let u_tt = u_t_plus
        .add(u_t_minus)
        .sub(u.clone().mul_scalar(two))
        .div_scalar(eps_fd * eps_fd);

    // 3. Assemble residual
    // LHS = ∇²u - μσ(∂u/∂t) - με(∂²u/∂t²)
    let term_diffusion = u_t.mul_scalar(mu as f32 * sigma as f32);
    let term_wave = u_tt.mul_scalar(mu as f32 * eps as f32);

    let lhs = laplacian.sub(term_diffusion).sub(term_wave);

    // RHS source term: -μJ
    // Residual = LHS + μJ
    let j_z = compute_current_density_z(x, y, physics_params);
    let source_term = j_z.mul_scalar(mu as f32);

    lhs.add(source_term)
}

pub fn wave_propagation_residual<B: AutodiffBackend>(
    model: &BurnPINN2DWave<B>, // Changed from outputs to model
    x: &Tensor<B, 2>,
    y: &Tensor<B, 2>,
    t: &Tensor<B, 2>,
    eps: f64,
    mu: f64,
    sigma: f64,
    physics_params: &PhysicsParameters,
) -> Tensor<B, 2> {
    // TODO_AUDIT: P1 - PINN Electromagnetic Wave Propagation Residual - Stub Implementation
    //
    // PROBLEM:
    // This function returns zero residuals, completely bypassing electromagnetic wave equation
    // enforcement in PINN training for time-dependent Maxwell problems.
    //
    // IMPACT:
    // - PINN cannot learn electromagnetic wave propagation dynamics
    // - Training loss for wave physics is always zero (no learning signal)
    // - No enforcement of full Maxwell equations: ∇×E = -∂B/∂t, ∇×H = J + ∂D/∂t, ∇·D = ρ, ∇·B = 0
    // - Blocks applications: waveguide simulation, antenna radiation, RF propagation, photonics
    // - Severity: P1 (research/advanced feature, not production-critical)
    //
    // REQUIRED IMPLEMENTATION:
    // 1. Compute E(x,y,t) and H(x,y,t) fields from model outputs or coupled models
    // 2. Compute spatial curl operators using autodiff:
    //    - ∇×E = (∂Ez/∂y - ∂Ey/∂z, ∂Ex/∂z - ∂Ez/∂x, ∂Ey/∂x - ∂Ex/∂y)
    //    - ∇×H = (∂Hz/∂y - ∂Hy/∂z, ∂Hx/∂z - ∂Hz/∂x, ∂Hy/∂x - ∂Hx/∂y)
    // 3. Compute time derivatives ∂E/∂t and ∂H/∂t using autodiff
    // 4. Form Maxwell equation residuals:
    //    R_Faraday = ∇×E + μ ∂H/∂t
    //    R_Ampere = ∇×H - σE - ε ∂E/∂t - J_ext
    // 5. Optionally enforce Gauss's laws: ∇·D = ρ, ∇·B = 0
    // 6. Return combined residual (e.g., L2 norm or concatenated components)
    //
    // MATHEMATICAL SPECIFICATION:
    // Full time-dependent Maxwell equations in 2D (TE/TM modes):
    //   TE mode (Ez, Hx, Hy):
    //     ∂Hz/∂y - ∂Hy/∂x = σEz + ε ∂Ez/∂t + Jz
    //     ∂Ez/∂x = -μ ∂Hy/∂t
    //     ∂Ez/∂y =  μ ∂Hx/∂t
    //   TM mode (Hz, Ex, Ey):
    //     ∂Ey/∂x - ∂Ex/∂y = σ_m Hz + μ ∂Hz/∂t + Mz
    //     ∂Hz/∂x = ε ∂Ey/∂t
    //     ∂Hz/∂y = -ε ∂Ex/∂t
    //
    // VALIDATION CRITERIA:
    // - Property test: Residual → 0 for analytical plane wave solutions
    // - Test case: TE₁₀ mode in rectangular waveguide (analytical dispersion relation)
    // - Test case: Gaussian pulse propagation in free space (verify c = 1/√(με))
    // - Test case: Reflection/transmission at dielectric interface (verify Fresnel coefficients)
    // - Convergence: Residual L2 norm < 1e-3 for analytical solutions after training
    // - Energy conservation: ∂/∂t ∫(εE²/2 + μH²/2)dV + ∫σE²dV + ∫S·n̂dA = 0 (Poynting theorem)
    //
    // REFERENCES:
    // - Jackson, J.D., "Classical Electrodynamics" (3rd ed.), Chapter 7: Plane Electromagnetic Waves
    // - Pozar, D.M., "Microwave Engineering" (4th ed.), Chapter 1: Electromagnetic Theory
    // - Taflove & Hagness, "Computational Electrodynamics: The Finite-Difference Time-Domain Method" (3rd ed.)
    // - Raissi et al., "Physics-informed neural networks"
    //
    // ESTIMATED EFFORT: 16-20 hours
    // - Implementation: 10-12 hours (curl operators, time derivatives, mode handling, residual assembly)
    // - Testing: 4-6 hours (waveguide modes, plane waves, interface validation)
    // - Documentation: 2 hours
    //
    // DEPENDENCIES:
    // - Requires proper vector field autodiff (curl, divergence operators)
    // - May need separate models for E and H fields, or coupled multi-output model
    // - Coordinate system handling for 2D mode decomposition (TE/TM)
    //
    // ASSIGNED: Sprint 212-213 (Research Features)
    // PRIORITY: P1 (Advanced electromagnetic wave simulation capability)

    // -------------------------------------------------------------------------
    // Theorem — Scalar Wave Equation for Ez (TM-mode Maxwell)
    //
    // In 2D TM polarisation (Ez, Hx, Hy fields; x–y plane; E field in z-direction):
    //   Faraday (Hx):  ∂Hx/∂t = -1/μ · ∂Ez/∂y
    //   Faraday (Hy):  ∂Hy/∂t =  1/μ · ∂Ez/∂x
    //   Ampere  (Ez):  ε·∂Ez/∂t = ∂Hy/∂x − ∂Hx/∂y − σ·Ez
    //
    // Eliminating Hx and Hy by taking ∂/∂t of the Ampere equation and
    // substituting the Faraday equations yields the scalar wave equation:
    //
    //   ε·μ·∂²Ez/∂t² + μ·σ·∂Ez/∂t = ∂²Ez/∂x² + ∂²Ez/∂y²
    //
    // PINN residual (zero on the exact solution):
    //   R = ε·μ·∂²Ez/∂t² + μ·σ·∂Ez/∂t − ∂²Ez/∂x² − ∂²Ez/∂y²
    //
    // Proof (plane-wave verification):
    //   Ez = exp(i(kx·x + ky·y − ωt)), kx² + ky² = ω²εμ − iωμσ
    //   → ε·μ·(−ω²Ez) + μ·σ·(−iωEz) + (kx² + ky²)Ez = 0  ✓
    //
    // Algorithm — second-order central finite-difference approximation:
    //   ∂²f/∂x² ≈ (f(x+h) − 2f(x) + f(x−h)) / h²   (O(h²))
    //   ∂f/∂t   ≈ (f(t+h) − f(t−h)) / (2h)           (O(h²))
    //   ∂²f/∂t² ≈ (f(t+h) − 2f(t) + f(t−h)) / h²    (O(h²))
    //
    // References:
    //   Jackson, J.D. (1999) "Classical Electrodynamics", 3rd ed., §6.2.
    //   Taflove & Hagness (2005) "Computational Electrodynamics", §3.4.
    //   Raissi, Perdikaris & Karniadakis (2019) J. Comput. Phys. 378:686–707.
    // -------------------------------------------------------------------------

    let _ = physics_params; // not required for the wave equation residual

    // Step size for finite differences (same pattern as other residuals in this file)
    let h = EPS_FD_F32;

    // --- ∂²Ez/∂x² = (Ez(x+h) − 2·Ez(x) + Ez(x−h)) / h² ---
    let ez_xp = model.forward(x.clone().add_scalar(h), y.clone(), t.clone());
    let ez_xm = model.forward(x.clone().sub_scalar(h), y.clone(), t.clone());
    let ez_0 = model.forward(x.clone(), y.clone(), t.clone());
    let d2ez_dx2 = (ez_xp.sub(ez_0.clone().mul_scalar(2.0)).add(ez_xm))
        .div_scalar(h * h);

    // --- ∂²Ez/∂y² = (Ez(y+h) − 2·Ez(y) + Ez(y−h)) / h² ---
    let ez_yp = model.forward(x.clone(), y.clone().add_scalar(h), t.clone());
    let ez_ym = model.forward(x.clone(), y.clone().sub_scalar(h), t.clone());
    let d2ez_dy2 = (ez_yp.sub(ez_0.clone().mul_scalar(2.0)).add(ez_ym))
        .div_scalar(h * h);

    // --- ∂²Ez/∂t² = (Ez(t+h) − 2·Ez(t) + Ez(t−h)) / h² ---
    let ez_tp = model.forward(x.clone(), y.clone(), t.clone().add_scalar(h));
    let ez_tm = model.forward(x.clone(), y.clone(), t.clone().sub_scalar(h));
    let d2ez_dt2 = (ez_tp.clone().sub(ez_0.clone().mul_scalar(2.0)).add(ez_tm.clone()))
        .div_scalar(h * h);

    // --- ∂Ez/∂t = (Ez(t+h) − Ez(t−h)) / (2h) ---
    let dez_dt = (ez_tp.sub(ez_tm)).div_scalar(2.0 * h);

    // --- Assemble residual: R = ε·μ·∂²Ez/∂t² + μ·σ·∂Ez/∂t − ∂²Ez/∂x² − ∂²Ez/∂y² ---
    let eps_mu = (eps * mu) as f32;
    let mu_sigma = (mu * sigma) as f32;

    let laplacian = d2ez_dx2.add(d2ez_dy2);
    let wave_term = d2ez_dt2.mul_scalar(eps_mu);
    let damping_term = dez_dt.mul_scalar(mu_sigma);

    wave_term.add(damping_term).sub(laplacian)
}

#[cfg(test)]
mod pinn_em_residuals_tests {
    /// For a constant Ez field (all inputs give the same output regardless of x, y, t),
    /// all derivatives are zero and the residual must be identically zero.
    ///
    /// Proof: if Ez(x,y,t) = C (constant), then
    ///   ∂²C/∂x² = ∂²C/∂y² = ∂²C/∂t² = ∂C/∂t = 0
    ///   → R = ε·μ·0 + μ·σ·0 − 0 − 0 = 0  ✓
    #[test]
    fn test_wave_propagation_residual_constant_field_is_zero() {
        // Use a trivially constant model: build a raw network that outputs a constant.
        // We approximate this by noting that the model forward for any (x,y,t)
        // produces the same output when the weights are near-zero with a constant bias.
        // For the residual to be exactly zero with FD, we just verify the formula
        // computes (c − 2c + c) / h² = 0 for the Laplacian of any uniform field.

        // The residual formula computes:
        //   d2ez_dx2 = (C − 2C + C) / h² = 0
        //   d2ez_dy2 = (C − 2C + C) / h² = 0
        //   d2ez_dt2 = (C − 2C + C) / h² = 0
        //   dez_dt   = (C − C) / (2h) = 0
        //   R = eps_mu * 0 + mu_sigma * 0 − 0 − 0 = 0  ✓

        let h = EPS_FD_F32;
        let c_val = 1.5_f32;
        let batch = 4_usize;

        // Simulate what the residual computes for a constant field:
        let d2_dx2: Vec<f32> = (0..batch)
            .map(|_| (c_val - 2.0 * c_val + c_val) / (h * h))
            .collect();
        let d2_dt2: Vec<f32> = d2_dx2.clone();
        let d_dt: Vec<f32> = (0..batch).map(|_| (c_val - c_val) / (2.0 * h)).collect();

        let eps_mu = 1.0_f32;
        let mu_sigma = 0.5_f32;

        let residuals: Vec<f32> = (0..batch)
            .map(|i| eps_mu * d2_dt2[i] + mu_sigma * d_dt[i] - d2_dx2[i] - d2_dx2[i])
            .collect();

        for r in &residuals {
            assert!(
                r.abs() < 1e-3,
                "constant-field residual must be ~0, got {}",
                r
            );
        }
    }

    /// For a pure temporal cosine Ez(t) = cos(ω·t), the Laplacian is zero and:
    ///   R = ε·μ·(−ω²cos(ωt)) + μ·σ·(−ω·sin(ωt))
    /// which is non-zero for ω > 0. This confirms the residual correctly
    /// detects a field that does NOT satisfy the free-space (σ=0) wave equation.
    #[test]
    fn test_wave_propagation_residual_temporal_cosine_nonzero() {
        let h = EPS_FD_F32;
        let omega = 2.0_f32 * std::f32::consts::PI * 1e9_f32; // 1 GHz
        let t0 = 1e-10_f32; // arbitrary time sample
        let eps_mu = 8.854e-12_f32 * 1.257e-6_f32; // free space ε₀μ₀
        let mu_sigma = 0.0_f32; // lossless

        // FD approximation of ∂²cos/∂t² at t0
        let d2_dt2 = ((omega * (t0 + h)).cos() - 2.0 * (omega * t0).cos()
            + (omega * (t0 - h)).cos())
            / (h * h);

        // Laplacian = 0 (no spatial variation)
        let residual = eps_mu * d2_dt2 - mu_sigma * (omega * t0).sin() - 0.0_f32 - 0.0_f32;

        // Expect non-zero (this field does not satisfy the wave equation unless c²k²=ω²)
        assert!(
            residual.abs() > 1e-6,
            "temporal cosine residual must be non-zero, got {}",
            residual
        );
    }

    /// Finite-difference step must lie well above the f32 cancellation floor.
    ///
    /// The cancellation floor for f32 central differences is ε_mach^(2/3) ≈ 2.4e-5.
    /// EPS_FD_F32 = 4.9e-3 must be at least 100× above this floor.
    #[test]
    fn test_eps_fd_above_cancellation_floor() {
        // Cancellation floor for f32 FD = ε_mach^(2/3)
        let cancellation_floor = (f32::EPSILON as f64).powf(2.0 / 3.0) as f32;
        assert!(
            EPS_FD_F32 > cancellation_floor * 100.0,
            "EPS_FD_F32 ({:.2e}) must be >100× above f32 cancellation floor ({:.2e})",
            EPS_FD_F32, cancellation_floor
        );
    }

    /// The optimal step h_opt = ε^(1/3) must be larger than the old (broken) value
    /// `(f32::EPSILON).sqrt() * 1e-2`.
    #[test]
    fn test_eps_fd_larger_than_old_broken_step() {
        let old_broken_step = f32::EPSILON.sqrt() * 1e-2_f32;
        assert!(
            EPS_FD_F32 > old_broken_step * 10.0,
            "EPS_FD_F32 ({:.2e}) should be >> old step ({:.2e})",
            EPS_FD_F32, old_broken_step
        );
    }

    /// Finite-difference step size must be in a physically reasonable range.
    #[test]
    fn test_fd_step_is_in_safe_range() {
        assert!(EPS_FD_F32 > 1e-4, "EPS_FD_F32 too small: {}", EPS_FD_F32);
        assert!(EPS_FD_F32 < 1e-1, "EPS_FD_F32 too large: {}", EPS_FD_F32);
    }

    // -----------------------------------------------------------------------
    // Tests for compute_charge_density
    // -----------------------------------------------------------------------

    /// Source-free dielectric bulk: ρ_free = 0.
    ///
    /// Proof: charge_density not set in domain_params → rho_0 = 0 → return zeros.
    #[cfg(feature = "pinn")]
    #[test]
    fn test_charge_density_zero_for_source_free_medium() {
        type B = burn::backend::Autodiff<burn::backend::NdArray<f32>>;
        use burn::tensor::Tensor;
        use crate::solver::inverse::pinn::ml::physics::PhysicsParameters;
        use std::collections::HashMap;

        let params = PhysicsParameters {
            material_properties: HashMap::new(),
            boundary_values: HashMap::new(),
            initial_values: HashMap::new(),
            domain_params: HashMap::new(),
        };
        let x: Tensor<B, 2> = Tensor::zeros([4, 1]);
        let y: Tensor<B, 2> = Tensor::zeros([4, 1]);

        let rho = super::compute_charge_density::<B>(&x, &y, &params);
        let rho_data: Vec<f32> = rho.into_data().to_vec().unwrap();
        for v in &rho_data {
            assert!(v.abs() < 1e-10, "expected ρ=0 for source-free medium, got {}", v);
        }
    }

    /// Uniform impressed charge density: all output elements = rho_0.
    ///
    /// Proof: domain_params["charge_density"] = ρ₀ → return tensor filled with ρ₀.
    #[cfg(feature = "pinn")]
    #[test]
    fn test_charge_density_uniform_matches_param() {
        type B = burn::backend::Autodiff<burn::backend::NdArray<f32>>;
        use burn::tensor::Tensor;
        use crate::solver::inverse::pinn::ml::physics::PhysicsParameters;
        use std::collections::HashMap;

        let rho_expected = 1.5e-3_f64;
        let mut domain = HashMap::new();
        domain.insert("charge_density".to_string(), rho_expected);
        let params = PhysicsParameters {
            material_properties: HashMap::new(),
            boundary_values: HashMap::new(),
            initial_values: HashMap::new(),
            domain_params: domain,
        };
        let x: Tensor<B, 2> = Tensor::zeros([3, 1]);
        let y: Tensor<B, 2> = Tensor::zeros([3, 1]);

        let rho = super::compute_charge_density::<B>(&x, &y, &params);
        let rho_data: Vec<f32> = rho.into_data().to_vec().unwrap();
        for v in &rho_data {
            let diff = (v - rho_expected as f32).abs();
            assert!(diff < 1e-5, "expected ρ={:.3e}, got {:.3e}", rho_expected, v);
        }
    }

    /// Gaussian charge density: peak at (x0,y0), decays with σ.
    ///
    /// At (x0,y0) the Gaussian equals 1, so ρ = ρ₀.
    #[cfg(feature = "pinn")]
    #[test]
    fn test_charge_density_gaussian_peak_at_centre() {
        type B = burn::backend::Autodiff<burn::backend::NdArray<f32>>;
        use burn::tensor::Tensor;
        use crate::solver::inverse::pinn::ml::physics::PhysicsParameters;
        use std::collections::HashMap;

        let rho_0 = 2.0_f64;
        let mut domain = HashMap::new();
        domain.insert("charge_density".to_string(), rho_0);
        domain.insert("charge_x0".to_string(), 0.5_f64);
        domain.insert("charge_y0".to_string(), 0.5_f64);
        domain.insert("charge_sigma".to_string(), 0.1_f64);
        let params = PhysicsParameters {
            material_properties: HashMap::new(),
            boundary_values: HashMap::new(),
            initial_values: HashMap::new(),
            domain_params: domain,
        };
        // Single point exactly at the Gaussian centre → exp(0) = 1 → ρ = ρ₀
        let x: Tensor<B, 2> = Tensor::from_data([[0.5_f32]]);
        let y: Tensor<B, 2> = Tensor::from_data([[0.5_f32]]);

        let rho = super::compute_charge_density::<B>(&x, &y, &params);
        let rho_data: Vec<f32> = rho.into_data().to_vec().unwrap();
        let diff = (rho_data[0] - rho_0 as f32).abs();
        assert!(diff < 1e-4, "Gaussian peak should equal ρ₀={:.2}, got {:.6}", rho_0, rho_data[0]);
    }

    // -----------------------------------------------------------------------
    // Tests for compute_current_density_z
    // -----------------------------------------------------------------------

    /// No sources or conductivity: J_z = 0 (source-free dielectric).
    #[cfg(feature = "pinn")]
    #[test]
    fn test_current_density_zero_for_dielectric() {
        type B = burn::backend::Autodiff<burn::backend::NdArray<f32>>;
        use burn::tensor::Tensor;
        use crate::solver::inverse::pinn::ml::physics::PhysicsParameters;
        use std::collections::HashMap;

        let params = PhysicsParameters {
            material_properties: HashMap::new(),
            boundary_values: HashMap::new(),
            initial_values: HashMap::new(),
            domain_params: HashMap::new(),
        };
        let x: Tensor<B, 2> = Tensor::zeros([5, 1]);
        let y: Tensor<B, 2> = Tensor::zeros([5, 1]);

        let jz = super::compute_current_density_z::<B>(&x, &y, &params);
        let jz_data: Vec<f32> = jz.into_data().to_vec().unwrap();
        for v in &jz_data {
            assert!(v.abs() < 1e-10, "expected J_z=0 for dielectric, got {}", v);
        }
    }

    /// Conduction current: J = σ·E_z,background.
    ///
    /// Proof: J_cond = σ·E_bg = 2.0·3.0 = 6.0 A/m².
    #[cfg(feature = "pinn")]
    #[test]
    fn test_current_density_conduction_proportional_to_sigma_and_ez() {
        type B = burn::backend::Autodiff<burn::backend::NdArray<f32>>;
        use burn::tensor::Tensor;
        use crate::solver::inverse::pinn::ml::physics::PhysicsParameters;
        use std::collections::HashMap;

        let sigma = 2.0_f64;
        let e_z_bg = 3.0_f64;
        let expected = (sigma * e_z_bg) as f32;

        let mut domain = HashMap::new();
        domain.insert("conductivity".to_string(), sigma);
        domain.insert("e_z_background".to_string(), e_z_bg);
        let params = PhysicsParameters {
            material_properties: HashMap::new(),
            boundary_values: HashMap::new(),
            initial_values: HashMap::new(),
            domain_params: domain,
        };
        let x: Tensor<B, 2> = Tensor::zeros([3, 1]);
        let y: Tensor<B, 2> = Tensor::zeros([3, 1]);

        let jz = super::compute_current_density_z::<B>(&x, &y, &params);
        let jz_data: Vec<f32> = jz.into_data().to_vec().unwrap();
        for v in &jz_data {
            let diff = (v - expected).abs();
            assert!(diff < 1e-4, "expected J_z=σ·E_z={}, got {}", expected, v);
        }
    }

    /// Uniform impressed current: all output elements equal current_density_z.
    #[cfg(feature = "pinn")]
    #[test]
    fn test_current_density_uniform_impressed() {
        type B = burn::backend::Autodiff<burn::backend::NdArray<f32>>;
        use burn::tensor::Tensor;
        use crate::solver::inverse::pinn::ml::physics::PhysicsParameters;
        use std::collections::HashMap;

        let j0 = 5.0_f64;
        let mut domain = HashMap::new();
        domain.insert("current_density_z".to_string(), j0);
        let params = PhysicsParameters {
            material_properties: HashMap::new(),
            boundary_values: HashMap::new(),
            initial_values: HashMap::new(),
            domain_params: domain,
        };
        let x: Tensor<B, 2> = Tensor::zeros([4, 1]);
        let y: Tensor<B, 2> = Tensor::zeros([4, 1]);

        let jz = super::compute_current_density_z::<B>(&x, &y, &params);
        let jz_data: Vec<f32> = jz.into_data().to_vec().unwrap();
        for v in &jz_data {
            let diff = (v - j0 as f32).abs();
            assert!(diff < 1e-4, "expected J_z={}, got {}", j0, v);
        }
    }
}

/// Compute the prescribed free charge density source term ρ (C/m³).
///
/// ## Physics — Gauss's Law (Maxwell I, differential form)
///
/// The electrostatic residual enforced by the PINN is:
/// ```text
/// ∇·(ε∇φ) + ρ_free = 0
/// ```
/// where ρ_free is the **impressed** (externally prescribed) free charge density.
/// For source-free dielectric bulk media (water, tissue), ρ_free = 0 — physically
/// correct and the most common case in acoustic-electromagnetic coupling.
///
/// For problems with finite charge distributions (space-charge layers, plasma
/// regions, membrane potentials), ρ_free is specified via `domain_params`:
/// - `"charge_density"` (C/m³): spatially-uniform source charge density
/// - `"charge_x0"`, `"charge_y0"`, `"charge_sigma"` (m): Gaussian distribution centre
///   and width, combined with `"charge_density"` as peak amplitude
///
/// ## Gaussian source (Plonus 1988, §3.2)
///
/// A volume charge distribution of total charge Q₀ in a sphere of radius σ:
/// ```text
/// ρ(r) = ρ₀ · exp(−((x−x₀)² + (y−y₀)²) / (2σ²))
/// ```
/// with `ρ₀ = domain_params["charge_density"]`, `x₀ = domain_params["charge_x0"]`,
/// `y₀ = domain_params["charge_y0"]`, `σ = domain_params["charge_sigma"]`.
///
/// If none of the Gaussian parameters are present, a spatially-uniform density is used.
///
/// ## Reference
///
/// - Jackson, J.D. (1999). *Classical Electrodynamics* (3rd ed.). Wiley. §1.5.
/// - Griffiths, D.J. (2017). *Introduction to Electrodynamics* (4th ed.). §2.3.
pub fn compute_charge_density<B: AutodiffBackend>(
    x: &Tensor<B, 2>,
    y: &Tensor<B, 2>,
    physics_params: &PhysicsParameters,
) -> Tensor<B, 2> {
    let rho_0 = physics_params
        .domain_params
        .get("charge_density")
        .copied()
        .unwrap_or(0.0) as f32;

    if rho_0 == 0.0 {
        // Source-free bulk: ρ_free = 0 (physically correct for dielectrics)
        return Tensor::zeros_like(x);
    }

    // Check for Gaussian distribution parameters
    let x0 = physics_params.domain_params.get("charge_x0").copied();
    let y0 = physics_params.domain_params.get("charge_y0").copied();
    let sigma = physics_params.domain_params.get("charge_sigma").copied();

    match (x0, y0, sigma) {
        (Some(x0), Some(y0), Some(sigma)) if sigma > 0.0 => {
            // Gaussian charge distribution: ρ(r) = ρ₀ · exp(−r²/(2σ²))
            // where r² = (x−x₀)² + (y−y₀)²
            let dx = x.clone().sub_scalar(x0 as f32);
            let dy = y.clone().sub_scalar(y0 as f32);
            let r_sq = dx.clone().mul(dx).add(dy.clone().mul(dy));
            let two_sigma_sq = (2.0 * sigma * sigma) as f32;
            r_sq.div_scalar(two_sigma_sq).neg().exp().mul_scalar(rho_0)
        }
        _ => {
            // Spatially-uniform charge density
            Tensor::zeros_like(x).add_scalar(rho_0)
        }
    }
}

/// Compute the z-component of impressed current density J_z (A/m²).
///
/// ## Physics — Ampère's Law (Maxwell IV, 2D TM-mode)
///
/// In the magnetostatic / quasi-static 2D TM formulation (Hz, Ex, Ey fields),
/// the z-direction Ampère equation is:
/// ```text
/// ∇×H|_z = ε·∂Ez/∂t + σ·Ez + J_ext,z
/// ```
/// This function evaluates the **impressed** source current J_ext,z at the
/// query collocation points. Conduction current (σ·Ez) is handled separately
/// by the PINN residual via the model's predicted Ez field; this function
/// supplies only the externally prescribed contribution.
///
/// ## Source parameterisation
///
/// `physics_params.domain_params` keys:
/// - `"current_density_z"` (A/m²): spatially-uniform impressed current
/// - `"current_x0"`, `"current_y0"`, `"current_sigma"` (m): Gaussian source
///   centre and half-width, combined with `"current_density_z"` as peak amplitude
/// - `"conductivity"` (S/m) + `"e_z_background"` (V/m): conduction background
///   J_cond = σ·E_z,background (constant background field approximation)
///
/// ## Gaussian line-source (Balanis 2012, §3.4)
///
/// A filamentary current of linear density K₀ spread over radius σ:
/// ```text
/// J_z(r) = K₀ · exp(−r²/(2σ²)) / (2πσ²)
/// ```
///
/// ## Reference
///
/// - Jackson, J.D. (1999). *Classical Electrodynamics* (3rd ed.). Wiley. §6.7.
/// - Pozar, D.M. (2011). *Microwave Engineering* (4th ed.). Wiley. §1.3.
/// - Balanis, C.A. (2012). *Advanced Engineering Electromagnetics* (2nd ed.). §3.4.
pub fn compute_current_density_z<B: AutodiffBackend>(
    x: &Tensor<B, 2>,
    y: &Tensor<B, 2>,
    physics_params: &PhysicsParameters,
) -> Tensor<B, 2> {
    // Conduction background: J_cond = σ·E_z,background (if both are specified)
    let sigma = physics_params
        .domain_params
        .get("conductivity")
        .copied()
        .unwrap_or(0.0);
    let e_z_bg = physics_params
        .domain_params
        .get("e_z_background")
        .copied()
        .unwrap_or(0.0);
    let j_cond = (sigma * e_z_bg) as f32;

    // Impressed source: uniform or Gaussian distribution
    let j0 = physics_params
        .domain_params
        .get("current_density_z")
        .copied()
        .unwrap_or(0.0) as f32;

    let j_impressed = if j0 != 0.0 {
        let x0 = physics_params.domain_params.get("current_x0").copied();
        let y0 = physics_params.domain_params.get("current_y0").copied();
        let sig = physics_params.domain_params.get("current_sigma").copied();
        match (x0, y0, sig) {
            (Some(cx), Some(cy), Some(s)) if s > 0.0 => {
                // Gaussian impressed current: J_z(r) = J₀·exp(−r²/(2σ²))
                let dx = x.clone().sub_scalar(cx as f32);
                let dy = y.clone().sub_scalar(cy as f32);
                let r_sq = dx.clone().mul(dx).add(dy.clone().mul(dy));
                let two_s2 = (2.0 * s * s) as f32;
                r_sq.div_scalar(two_s2).neg().exp().mul_scalar(j0)
            }
            _ => Tensor::zeros_like(x).add_scalar(j0),
        }
    } else {
        Tensor::zeros_like(x)
    };

    // Total impressed current (conduction background + external source)
    j_impressed.add_scalar(j_cond)
}

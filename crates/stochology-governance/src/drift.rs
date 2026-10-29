//! Formal Drift Adaptation and Murphy-CORP Circuit Breaker across the 4 Regimes of Drift (§4.2):
//! 1. **Covariate Drift** ($Q(X) \neq P(X)$, $Q(Y \mid X) = P(Y \mid X)$): Exponential Tilt $\hat{w}(x)$
//!    and Weighted Conformal Prediction (*ExTRA-WCP-T*) with Lei & Candès coverage bound $1 - \alpha - d_{\mathrm{TV}}(Q, \hat{Q})$;
//! 2. **Label / Prior Probability Shift** ($Q(Y) \neq P(Y)$, $Q(X \mid Y) = P(X \mid Y)$): Four canonical
//!    estimators (**BBSE**, **MLLS/SLD**, **DFM**, and **OTTER**);
//! 3. **Concept / Structural Drift** ($Q(Y \mid X) \neq P(Y \mid X)$): Murphy-CORP circuit breaker;
//! 4. **Performative Feedback** ($\mathcal{D}(\theta)$): Stackelberg equilibrium / RRM contraction audit.

use stochology_core::quantile;
use stochology_lenses::decision::CorpPavDecomposition;

/// The Four Regimes of Production Drift (§4.2).
#[derive(Debug, Clone, Copy, PartialEq, Eq)]
pub enum DriftRegime {
    Stationary,
    CovariateDrift,
    LabelShift,
    ConceptDriftCircuitBreaker,
    PerformativeFeedback,
}

/// Continuous Production Monitor and Circuit Breaker based on Isotonic CORP-Murphy Decomposition (§4.2).
#[derive(Debug, Clone, PartialEq)]
pub struct MurphyCorpCircuitBreaker {
    pub rel_miscalibration: f64,
    pub res_resolution: f64,
    pub unc0_uncertainty: f64,
    pub circuit_breaker_tripped: bool,
    pub diagnosed_regime: DriftRegime,
    pub recommended_corrective_action: String,
}

impl MurphyCorpCircuitBreaker {
    /// Evaluates rolling predictions and outcomes against `max_rel_threshold` and `min_res_threshold`.
    pub fn monitor(
        forecasts_p: &[f64],
        outcomes_y: &[f64],
        max_rel_threshold: f64,
        min_res_threshold: f64,
        covariate_shift_detected: bool,
        label_shift_detected: bool,
        performative_loop_active: bool,
    ) -> Self {
        let corp = CorpPavDecomposition::compute(forecasts_p, outcomes_y);
        let rel_degraded = corp.rel_miscalibration > max_rel_threshold;
        let res_collapsed = corp.res_resolution < min_res_threshold;

        let (tripped, regime, action) = if res_collapsed {
            (
                true,
                DriftRegime::ConceptDriftCircuitBreaker,
                "TRIP CIRCUIT BREAKER: RES_CORP collapsed below threshold (Concept Drift Q(Y|X) != P(Y|X)); suspend automated decisions and re-enter SIGA Funnel".into(),
            )
        } else if performative_loop_active {
            (
                rel_degraded,
                DriftRegime::PerformativeFeedback,
                "Performative feedback D(theta) active: audit RRM contraction (eps*beta/gamma < 1) and transition to Stackelberg optimum theta_PO".into(),
            )
        } else if label_shift_detected || rel_degraded {
            (
                false,
                DriftRegime::LabelShift,
                "RES_CORP preserved while REL_CORP shifted: apply Label Shift Bayes update via BBSE / MLLS / DFM / OTTER without full retraining".into(),
            )
        } else if covariate_shift_detected {
            (
                false,
                DriftRegime::CovariateDrift,
                "Covariate Drift Q(X) != P(X) with stable conditional physics: apply Exponential Tilt w_hat(x) and ExTRA-WCP-T conformal threshold".into(),
            )
        } else {
            (
                false,
                DriftRegime::Stationary,
                "Stationary regime: REL_CORP and RES_CORP within pre-registered operating bounds"
                    .into(),
            )
        };

        Self {
            rel_miscalibration: corp.rel_miscalibration,
            res_resolution: corp.res_resolution,
            unc0_uncertainty: corp.unc0_uncertainty,
            circuit_breaker_tripped: tripped,
            diagnosed_regime: regime,
            recommended_corrective_action: action,
        }
    }
}

/// Adaptation to Covariate Drift via Exponential Tilt and Weighted Conformal Prediction
/// (*ExTRA-WCP-T*) with Lei & Candès Total Variation Bound (§4.2).
///
/// Estimates $\beta$ by maximizing $\hat{L}(\beta) = \frac{1}{m}\sum_{j=1}^m \ln M_\beta(X_j^Q) - \ln Z_P(\beta) - \frac{\lambda}{2}\|\beta\|_2^2$
/// and computes the exact lower coverage bound:
/// $$\mathbb{P}_{P^n \times Q}\{Y_{n+1} \in C_{S, \hat{w}}(X_{n+1}) \mid \mathcal{F}\} \ge 1 - \alpha - d_{\mathrm{TV}}(Q, \hat{Q}), \qquad d_{\mathrm{TV}}(Q, \hat{Q}) = \frac{1}{2}\mathbb{E}_P|w^\star - \hat{w}|$$
#[derive(Debug, Clone, PartialEq)]
pub struct CovariateDriftResult {
    pub estimated_beta: f64,
    pub normalizing_constant_z_p: f64,
    pub regularized_objective_l_hat: f64,
    pub total_variation_distance_d_tv: f64,
    pub nominal_level_one_minus_alpha: f64,
    pub lei_candes_coverage_lower_bound: f64,
    pub weighted_conformal_threshold: f64,
}

pub fn fit_covariate_drift_extra_wcp(
    x_source_p: &[f64],
    x_target_q: &[f64],
    nonconformity_scores_source: &[f64],
    true_weights_optional: Option<&[f64]>,
    lambda_reg: f64,
    alpha: f64,
) -> CovariateDriftResult {
    assert!(!x_source_p.is_empty() && !x_target_q.is_empty());
    assert_eq!(x_source_p.len(), nonconformity_scores_source.len());
    let mean_q = stochology_core::mean(x_target_q);

    // Concave 1D Newton optimization for L_hat(beta) = beta * mean_Q(x) - ln E_P[exp(beta * x)] - 0.5 * lambda * beta^2
    let mut beta = 0.0_f64;
    for _ in 0..40 {
        let max_bx = x_source_p
            .iter()
            .map(|&x| beta * x)
            .fold(f64::NEG_INFINITY, f64::max);
        let exp_weights: Vec<f64> = x_source_p
            .iter()
            .map(|&x| (beta * x - max_bx).exp())
            .collect();
        let sum_w: f64 = exp_weights.iter().sum();
        let e_x: f64 = x_source_p
            .iter()
            .zip(exp_weights.iter())
            .map(|(&x, &w)| x * w)
            .sum::<f64>()
            / sum_w;
        let e_x2: f64 = x_source_p
            .iter()
            .zip(exp_weights.iter())
            .map(|(&x, &w)| x * x * w)
            .sum::<f64>()
            / sum_w;
        let grad = mean_q - e_x - lambda_reg * beta;
        let hess = (e_x2 - e_x * e_x + lambda_reg).max(1e-6);
        beta += grad / hess;
    }

    let max_bx = x_source_p
        .iter()
        .map(|&x| beta * x)
        .fold(f64::NEG_INFINITY, f64::max);
    let exp_shifted: Vec<f64> = x_source_p
        .iter()
        .map(|&x| (beta * x - max_bx).exp())
        .collect();
    let mean_shifted = stochology_core::mean(&exp_shifted);
    let z_p = mean_shifted * max_bx.exp();
    let w_hat: Vec<f64> = exp_shifted.iter().map(|&e| e / mean_shifted).collect();
    let l_hat = beta * mean_q - (max_bx + mean_shifted.ln()) - 0.5 * lambda_reg * beta * beta;

    // Total Variation distance d_TV(Q, Q_hat):
    // Uses exact 0.5 * E_P[|w* - w_hat|] when oracle weights w* are provided; otherwise uses the
    // empirical 10-decile-bin L1 Total Variation distance (and Gaussian Pinsker bound) between
    // target sample Q and tilted source distribution (x_source_p, w_hat).
    let d_tv = if let Some(w_star) = true_weights_optional {
        0.5 * w_star
            .iter()
            .zip(w_hat.iter())
            .map(|(&ws, &wh)| (ws - wh).abs())
            .sum::<f64>()
            / (w_hat.len() as f64)
    } else {
        let sum_wh: f64 = w_hat.iter().sum::<f64>().max(1e-12);
        let mu_q_hat: f64 = x_source_p
            .iter()
            .zip(w_hat.iter())
            .map(|(&x, &w)| x * w)
            .sum::<f64>()
            / sum_wh;
        let var_q_hat: f64 = (x_source_p
            .iter()
            .zip(w_hat.iter())
            .map(|(&x, &w)| (x - mu_q_hat).powi(2) * w)
            .sum::<f64>()
            / sum_wh)
            .max(1e-6);
        let var_q: f64 = if x_target_q.len() >= 2 {
            stochology_core::sample_variance(x_target_q).max(1e-6)
        } else {
            var_q_hat
        };
        let kl_gauss = 0.5
            * ((var_q_hat / var_q).ln() + (var_q + (mean_q - mu_q_hat).powi(2)) / var_q_hat - 1.0)
                .max(0.0);
        let tv_gauss = (0.5 * kl_gauss).sqrt();
        let tv_decile = empirical_decile_tv_distance(x_source_p, &w_hat, x_target_q);
        tv_gauss.max(tv_decile).clamp(0.0, 1.0)
    };

    // Weighted quantile (ExTRA-WCP-T) of nonconformity scores with Lei-Candès TV-adjusted level (1 - alpha + d_TV)
    let mut pairs: Vec<(f64, f64)> = nonconformity_scores_source
        .iter()
        .copied()
        .zip(w_hat.iter().copied())
        .collect();
    pairs.sort_by(|a, b| a.0.total_cmp(&b.0));
    let sum_weights: f64 = pairs.iter().map(|(_, w)| *w).sum::<f64>() + 1.0;
    let effective_quantile_level = (1.0 - alpha + d_tv).clamp(0.0, 1.0);
    let target_cum = effective_quantile_level * sum_weights;
    let mut cum = 0.0;
    let mut conformal_threshold = pairs
        .last()
        .map(|p| p.0)
        .unwrap_or(quantile(nonconformity_scores_source, 1.0 - alpha));
    for (s, w) in pairs {
        cum += w;
        if cum >= target_cum {
            conformal_threshold = s;
            break;
        }
    }

    let lei_candes_bound = (1.0 - alpha - d_tv).max(0.0);

    CovariateDriftResult {
        estimated_beta: beta,
        normalizing_constant_z_p: z_p,
        regularized_objective_l_hat: l_hat,
        total_variation_distance_d_tv: d_tv,
        nominal_level_one_minus_alpha: 1.0 - alpha,
        lei_candes_coverage_lower_bound: lei_candes_bound,
        weighted_conformal_threshold: conformal_threshold,
    }
}

/// Auditable Estimators for Label / Prior Probability Shift (§4.2):
/// **BBSE**, **MLLS/SLD**, **DFM**, and **OTTER**.
#[derive(Debug, Clone, Copy, PartialEq)]
pub struct LabelShiftDiagnostic {
    /// Base rate in the source distribution $P_Y(y=1)$.
    pub source_prior_p1: f64,
    /// BBSE estimate (Lipton, Wang & Smola): $\hat{\omega} = C^{-1}\hat{\mu}_t$.
    pub target_prior_bbse: f64,
    /// Smallest singular value $\sigma_{\min}(C)$ of the source confusion matrix (spectral condition $\sigma_{\min}(C) > 0$).
    pub confusion_matrix_sigma_min: f64,
    /// MLLS / SLD estimate (Saerens-Latinne-Decaestecker EM over calibrated posteriors).
    pub target_prior_mlls_sld: f64,
    /// DFM (*Distribution Feature Matching*) estimate and novel-class contamination fraction $\alpha_0^*$.
    pub target_prior_dfm: f64,
    pub novel_class_contamination_alpha0: f64,
    /// Second smallest eigenvalue $\Delta_{\min}$ of the centered Gram matrix in DFM.
    pub gram_eigenvalue_delta_min: f64,
    /// OTTER estimate (*Optimal Transport* with cost $C_{ij} = -\ln P_\theta(Y=j \mid X=x_i)$).
    pub target_prior_otter: f64,
    /// Hoffman stability constant $\kappa$ of the OTTER optimal transport linear program.
    pub hoffman_constant_kappa: f64,
}

/// Computes the exact algebraic Bayes posterior update under Label Shift:
/// $$Q(y = 1 \mid x) = \frac{\omega_1 P(y=1 \mid x)}{\omega_1 P(y=1 \mid x) + \omega_0 (1 - P(y=1 \mid x))}$$
/// where $\omega_1 = \frac{Q_Y(1)}{P_Y(1)}$ and $\omega_0 = \frac{1 - Q_Y(1)}{1 - P_Y(1)}$.
#[inline]
pub fn adjust_posterior_for_label_shift(
    p_source_given_x: f64,
    source_prior_p1: f64,
    target_prior_q1: f64,
) -> f64 {
    let w1 = target_prior_q1 / source_prior_p1.max(1e-12);
    let w0 = (1.0 - target_prior_q1) / (1.0 - source_prior_p1).max(1e-12);
    let num = w1 * p_source_given_x;
    let den = num + w0 * (1.0 - p_source_given_x);
    if den <= 0.0 {
        target_prior_q1
    } else {
        (num / den).clamp(1e-6, 1.0 - 1e-6)
    }
}

/// Executes all four canonical Label Shift estimators (**BBSE**, **MLLS/SLD**, **DFM**, and **OTTER**) without target labels.
#[allow(clippy::too_many_arguments)]
pub fn estimate_label_shift_four_methods(
    source_prior_p1: f64,
    source_tpr: f64,
    source_fpr: f64,
    target_calibrated_posteriors: &[f64],
    source_class0_feature_mean: f64,
    source_class1_feature_mean: f64,
    target_feature_mean: f64,
    novel_class_contamination_alpha0: f64,
) -> LabelShiftDiagnostic {
    assert!(!target_calibrated_posteriors.is_empty());

    // 1. BBSE (Black Box Shift Estimation, Lipton, Wang & Smola):
    // Compute the Bayes-consistent posterior threshold separating y_hat=0 and y_hat=1 under source (p1, TPR, FPR):
    let p_s_given_pos = (source_prior_p1 * source_tpr)
        / (source_prior_p1 * source_tpr + (1.0 - source_prior_p1) * source_fpr).max(1e-12);
    let p_s_given_neg = (source_prior_p1 * (1.0 - source_tpr))
        / (source_prior_p1 * (1.0 - source_tpr) + (1.0 - source_prior_p1) * (1.0 - source_fpr))
            .max(1e-12);
    let bayes_threshold = source_prior_p1.clamp(
        p_s_given_neg.min(p_s_given_pos),
        p_s_given_pos.max(p_s_given_neg),
    );

    let pred_pos_rate = target_calibrated_posteriors
        .iter()
        .filter(|&&p| p >= bayes_threshold)
        .count() as f64
        / (target_calibrated_posteriors.len() as f64);
    let diff_rates = source_tpr - source_fpr;
    let q1_bbse = if diff_rates.abs() < 1e-6 {
        source_prior_p1.clamp(0.001, 0.999)
    } else {
        ((pred_pos_rate - source_fpr) / diff_rates).clamp(0.001, 0.999)
    };
    // Exact smallest singular value of 2x2 joint confusion matrix C
    let c00 = (1.0 - source_fpr) * (1.0 - source_prior_p1);
    let c01 = source_fpr * (1.0 - source_prior_p1);
    let c10 = (1.0 - source_tpr) * source_prior_p1;
    let c11 = source_tpr * source_prior_p1;
    let sigma_min = smallest_singular_value_2x2(c00, c01, c10, c11);

    // 2. MLLS / SLD (Saerens-Latinne-Decaestecker EM algorithm):
    let mut q1_mlls = source_prior_p1.clamp(0.01, 0.99);
    for _ in 0..80 {
        let sum_post: f64 = target_calibrated_posteriors
            .iter()
            .map(|&p| adjust_posterior_for_label_shift(p, source_prior_p1, q1_mlls))
            .sum();
        q1_mlls = (sum_post / (target_calibrated_posteriors.len() as f64)).clamp(0.001, 0.999);
    }

    // 3. DFM (Distribution Feature Matching) with Generalized Label Shift (novel class contamination alpha_0*):
    let diff_mu = source_class1_feature_mean - source_class0_feature_mean;
    let delta_min = diff_mu * diff_mu;
    let effective_scale = (1.0 - novel_class_contamination_alpha0).clamp(0.01, 1.0);
    let q1_dfm = if diff_mu.abs() < 1e-12 {
        source_prior_p1.clamp(0.001, 0.999)
    } else {
        ((target_feature_mean - source_class0_feature_mean) / (effective_scale * diff_mu))
            .clamp(0.001, 0.999)
    };

    // 4. Entropic Optimal Transport 1D Sinkhorn-Knopp Label Shift Estimator (OTTER grid search
    // on cost matrix C_{ij} = -ln P_theta(Y=j | X=x_i)):
    let q1_otter = solve_otter_sinkhorn(
        source_prior_p1,
        source_tpr,
        source_fpr,
        pred_pos_rate,
        target_calibrated_posteriors,
    );
    // Exact Hoffman stability constant kappa(M) = 1 / sigma_min(M) of conditional operator M
    let sigma_min_m =
        smallest_singular_value_2x2(1.0 - source_fpr, 1.0 - source_tpr, source_fpr, source_tpr);
    let hoffman_kappa = 1.0 / sigma_min_m.max(1e-6);

    LabelShiftDiagnostic {
        source_prior_p1,
        target_prior_bbse: q1_bbse,
        confusion_matrix_sigma_min: sigma_min,
        target_prior_mlls_sld: q1_mlls,
        target_prior_dfm: q1_dfm,
        novel_class_contamination_alpha0,
        gram_eigenvalue_delta_min: delta_min,
        target_prior_otter: q1_otter,
        hoffman_constant_kappa: hoffman_kappa,
    }
}

/// Non-parametric empirical quantile-bin $L_1$ Total Variation distance between the target sample
/// `x_target_q` and the tilted source distribution `(x_source_p, w_hat)` across 10 pooled decile bins.
fn empirical_decile_tv_distance(x_source_p: &[f64], w_hat: &[f64], x_target_q: &[f64]) -> f64 {
    let mut pooled = Vec::with_capacity(x_source_p.len() + x_target_q.len());
    pooled.extend_from_slice(x_source_p);
    pooled.extend_from_slice(x_target_q);
    pooled.sort_by(|a, b| a.total_cmp(b));
    if pooled.is_empty() {
        return 0.0;
    }
    let mut cuts = [0.0_f64; 9];
    for (k, cut) in cuts.iter_mut().enumerate() {
        *cut = stochology_core::quantile_sorted(&pooled, ((k + 1) as f64) * 0.10);
    }
    let bin_index = |x: f64| -> usize {
        for (k, &c) in cuts.iter().enumerate() {
            if x <= c {
                return k;
            }
        }
        9
    };

    let mut p_bins = [0.0_f64; 10];
    let sum_w = w_hat.iter().sum::<f64>().max(1e-12);
    for (&x, &w) in x_source_p.iter().zip(w_hat.iter()) {
        p_bins[bin_index(x)] += w / sum_w;
    }

    let mut q_bins = [0.0_f64; 10];
    let inv_m = 1.0 / (x_target_q.len().max(1) as f64);
    for &x in x_target_q {
        q_bins[bin_index(x)] += inv_m;
    }

    0.5 * (0..10).map(|b| (p_bins[b] - q_bins[b]).abs()).sum::<f64>()
}

/// Fits a calibrated 1D logistic classifier $P(Y=1 \mid X=x) = \sigma(\beta_0 + \beta_1 x)$ on `(x_source, y_source)`
/// via Newton-Raphson (IRLS) and evaluates it on `x_target`.
///
/// Returns `(source_prior_p1, source_tpr, source_fpr, source_class0_mean, source_class1_mean, target_posteriors)`.
pub fn fit_calibrated_logistic_1d(
    x_source: &[f64],
    y_source: &[f64],
    x_target: &[f64],
) -> (f64, f64, f64, f64, f64, Vec<f64>) {
    assert!(!x_source.is_empty() && x_source.len() == y_source.len());
    let n = x_source.len() as f64;
    let p_base = (y_source.iter().sum::<f64>() / n).clamp(0.001, 0.999);
    let mut b0 = (p_base / (1.0 - p_base)).ln();
    let mut b1 = 0.0_f64;

    for _ in 0..25 {
        let mut g0 = 0.0;
        let mut g1 = 0.0;
        let mut h00 = 1e-4;
        let mut h01 = 0.0;
        let mut h11 = 1e-4;
        for (&x, &y) in x_source.iter().zip(y_source.iter()) {
            let z = (b0 + b1 * x).clamp(-20.0, 20.0);
            let p = 1.0 / (1.0 + (-z).exp());
            let w = (p * (1.0 - p)).max(1e-6);
            let diff = y - p;
            g0 += diff;
            g1 += diff * x;
            h00 += w;
            h01 += w * x;
            h11 += w * x * x;
        }
        let det = (h00 * h11 - h01 * h01).max(1e-9);
        b0 += (h11 * g0 - h01 * g1) / det;
        b1 += (-h01 * g0 + h00 * g1) / det;
    }

    let mut sum0 = 0.0;
    let mut cnt0 = 0usize;
    let mut sum1 = 0.0;
    let mut cnt1 = 0usize;
    let mut tp = 0usize;
    let mut fp = 0usize;
    for (&x, &y) in x_source.iter().zip(y_source.iter()) {
        let p = 1.0 / (1.0 + (-(b0 + b1 * x).clamp(-20.0, 20.0)).exp());
        let pred_pos = p >= p_base;
        if y >= 0.5 {
            sum1 += x;
            cnt1 += 1;
            if pred_pos {
                tp += 1;
            }
        } else {
            sum0 += x;
            cnt0 += 1;
            if pred_pos {
                fp += 1;
            }
        }
    }
    let mu0 = sum0 / (cnt0.max(1) as f64);
    let mu1 = sum1 / (cnt1.max(1) as f64);
    let tpr = (tp as f64 / (cnt1.max(1) as f64)).clamp(0.05, 0.95);
    let fpr = (fp as f64 / (cnt0.max(1) as f64)).clamp(0.01, (tpr - 0.02).max(0.02));
    let target_posteriors: Vec<f64> = x_target
        .iter()
        .map(|&x| {
            let p = 1.0 / (1.0 + (-(b0 + b1 * x).clamp(-20.0, 20.0)).exp());
            p.clamp(0.001, 0.999)
        })
        .collect();

    (p_base, tpr, fpr, mu0, mu1, target_posteriors)
}

/// Exact smallest singular value $\sigma_{\min}(A)$ of a $2 \times 2$ matrix $\begin{pmatrix} a & b \\ c & d \end{pmatrix}$.
fn smallest_singular_value_2x2(a: f64, b: f64, c: f64, d: f64) -> f64 {
    let frob2 = a * a + b * b + c * c + d * d;
    let det = (a * d - b * c).abs();
    let disc = (frob2 * frob2 - 4.0 * det * det).max(0.0).sqrt();
    (0.5 * (frob2 - disc)).max(0.0).sqrt()
}

/// Solves the Entropic Optimal Transport Label Shift problem (OTTER) via Sinkhorn-Knopp matrix scaling
/// on cost $C_{i,j} = -\ln P_\theta(Y=j \mid X=x_i)$ coupled with confusion operator $M$.
fn solve_otter_sinkhorn(
    source_prior_p1: f64,
    source_tpr: f64,
    source_fpr: f64,
    target_pred_pos_rate: f64,
    target_posteriors: &[f64],
) -> f64 {
    let n = target_posteriors.len();
    let inv_n = 1.0 / (n as f64);
    let p1_s = source_prior_p1.clamp(1e-6, 1.0 - 1e-6);
    let p0_s = 1.0 - p1_s;
    let mu_t = [
        (1.0 - target_pred_pos_rate).clamp(1e-6, 1.0 - 1e-6),
        target_pred_pos_rate.clamp(1e-6, 1.0 - 1e-6),
    ];

    // Gibbs kernel K_{i,j} = exp(-C_{i,j} / eps_ot) with class-conditional likelihood weighting
    let mut k_mat = Vec::with_capacity(n);
    for &p in target_posteriors {
        let pc = p.clamp(1e-6, 1.0 - 1e-6);
        // C_{i,j} = -ln P_theta(Y=j | X=x_i) adjusted by source prior so K_{i,j} proportional to P(X_i | Y=j)
        let k0 = (1.0 - pc) / p0_s;
        let k1 = pc / p1_s;
        k_mat.push([k0.max(1e-12), k1.max(1e-12)]);
    }

    // Evaluate Entropic Optimal Transport / Sinkhorn divergence objective over candidate target marginals q = (1 - q1, q1)
    let eval_sinkhorn = |q1: f64| -> f64 {
        let q = [1.0 - q1, q1];
        let mut u = vec![1.0; n];
        let mut v = [1.0, 1.0];
        for _ in 0..15 {
            for (i, u_i) in u.iter_mut().enumerate() {
                let denom = k_mat[i][0] * v[0] + k_mat[i][1] * v[1];
                *u_i = inv_n / denom.max(1e-15);
            }
            for j in 0..2 {
                let col_sum: f64 = (0..n).map(|i| u[i] * k_mat[i][j]).sum();
                v[j] = q[j] / col_sum.max(1e-15);
            }
        }

        // Confusion-pushed target marginal M * q = [(1 - FPR)(1 - q1) + (1 - TPR)q1, FPR(1 - q1) + TPR * q1]
        let mq = [
            ((1.0 - source_fpr) * q[0] + (1.0 - source_tpr) * q[1]).clamp(1e-9, 1.0 - 1e-9),
            (source_fpr * q[0] + source_tpr * q[1]).clamp(1e-9, 1.0 - 1e-9),
        ];
        let kl_confusion = mu_t[0] * (mu_t[0] / mq[0]).ln() + mu_t[1] * (mu_t[1] / mq[1]).ln();

        // Sinkhorn dual KL consistency on k_mat between scaled coupling Pi = diag(u) K diag(v)
        // and the unscaled Bayes reference coupling Pi^(0)_{i,j} = (1/n) * K_{i,j} q_j / (K_{i,0} q_0 + K_{i,1} q_1)
        let mut kl_sinkhorn = 0.0;
        for i in 0..n {
            let ref_denom = (k_mat[i][0] * q[0] + k_mat[i][1] * q[1]).max(1e-15);
            for j in 0..2 {
                let pi_ij = (u[i] * k_mat[i][j] * v[j]).max(1e-15);
                let pi0_ij = (inv_n * k_mat[i][j] * q[j] / ref_denom).max(1e-15);
                kl_sinkhorn += pi_ij * (pi_ij / pi0_ij).ln();
            }
        }
        kl_confusion.max(0.0) + kl_sinkhorn.max(0.0)
    };

    let mut best_q1 = source_prior_p1.clamp(0.001, 0.999);
    let mut best_obj = f64::INFINITY;
    for step in 1..200 {
        let q1 = (step as f64) / 200.0;
        let obj = eval_sinkhorn(q1);
        if obj < best_obj {
            best_obj = obj;
            best_q1 = q1;
        }
    }
    // Golden-section sub-grid refinement around best_q1
    let inv_phi = 0.5 * (5.0_f64.sqrt() - 1.0);
    let mut a = (best_q1 - 0.01).clamp(0.001, 0.999);
    let mut b = (best_q1 + 0.01).clamp(0.001, 0.999);
    let mut c = b - inv_phi * (b - a);
    let mut d = a + inv_phi * (b - a);
    let mut fc = eval_sinkhorn(c);
    let mut fd = eval_sinkhorn(d);
    for _ in 0..32 {
        if fc <= fd {
            b = d;
            d = c;
            fd = fc;
            c = b - inv_phi * (b - a);
            fc = eval_sinkhorn(c);
        } else {
            a = c;
            c = d;
            fc = fd;
            d = a + inv_phi * (b - a);
            fd = eval_sinkhorn(d);
        }
    }
    (0.5 * (a + b)).clamp(0.001, 0.999)
}

/// Online Adaptive Conformal Inference (ACI, Gibbs & Candès 2021, *NeurIPS*) under arbitrary
/// non-exchangeable distribution shift:
/// $$\alpha_{t+1} = \mathrm{clamp}\bigl(\alpha_t + \gamma (\alpha_{\text{target}} - \mathrm{err}_t),\ 0.001,\ 0.999\bigr)$$
/// where $\mathrm{err}_t = \mathbb{I}\{Y_t \notin \hat{C}_t(X_t; 1 - \alpha_t)\}$. Guarantees long-run coverage
/// $\lim_{T \to \infty} \frac{1}{T}\sum_{t=1}^T (1 - \mathrm{err}_t) = 1 - \alpha_{\text{target}}$ without exchangeability!
#[derive(Debug, Clone, PartialEq)]
pub struct AdaptiveConformalInference {
    pub target_miscoverage_alpha: f64,
    pub step_size_gamma: f64,
    pub empirical_coverage_aci: f64,
    pub empirical_coverage_static: f64,
    pub final_alpha_t: f64,
    pub alpha_trajectory: Vec<f64>,
}

impl AdaptiveConformalInference {
    /// Evaluates online ACI against a static conformal quantile on calibration scores `calibration_scores`
    /// and a shifting out-of-sample test stream `test_nonconformity_scores`.
    pub fn evaluate_stream(
        calibration_scores: &[f64],
        test_nonconformity_scores: &[f64],
        target_miscoverage_alpha: f64,
        step_size_gamma: f64,
    ) -> Self {
        assert!(!calibration_scores.is_empty() && !test_nonconformity_scores.is_empty());
        assert!(target_miscoverage_alpha > 0.0 && target_miscoverage_alpha < 1.0);
        assert!(step_size_gamma > 0.0);

        let mut sorted_cal = calibration_scores.to_vec();
        sorted_cal.sort_by(|a, b| a.total_cmp(b));
        let q_static =
            stochology_core::quantile_sorted(&sorted_cal, 1.0 - target_miscoverage_alpha);

        let mut alpha_t = target_miscoverage_alpha;
        let mut traj = Vec::with_capacity(test_nonconformity_scores.len() + 1);
        traj.push(alpha_t);

        let mut covered_aci = 0usize;
        let mut covered_static = 0usize;

        for &s_t in test_nonconformity_scores {
            if s_t <= q_static {
                covered_static += 1;
            }
            let q_t =
                stochology_core::quantile_sorted(&sorted_cal, (1.0 - alpha_t).clamp(0.001, 0.999));
            let err_t = if s_t > q_t { 1.0 } else { 0.0 };
            if err_t == 0.0 {
                covered_aci += 1;
            }
            alpha_t = (alpha_t + step_size_gamma * (target_miscoverage_alpha - err_t))
                .clamp(0.001, 0.999);
            traj.push(alpha_t);
        }

        let t_len = test_nonconformity_scores.len() as f64;
        Self {
            target_miscoverage_alpha,
            step_size_gamma,
            empirical_coverage_aci: (covered_aci as f64) / t_len,
            empirical_coverage_static: (covered_static as f64) / t_len,
            final_alpha_t: alpha_t,
            alpha_trajectory: traj,
        }
    }
}

/// Traffic-light zone of the Basel III FRTB MAR33 Profit & Loss Attribution Test (`PLAT`).
#[derive(Debug, Clone, Copy, PartialEq, Eq)]
pub enum PlatTrafficLightZone {
    /// **Green Zone ($r_s > 0.80$ and $D_{\mathrm{KS}} < 0.09$):** Model risk-theoretical loss aligns with realized hypothetical loss.
    Green,
    /// **Amber Zone:** Intermediate divergence requiring capital surcharge and `S3*` supervision.
    Amber,
    /// **Red Zone ($r_s < 0.70$ or $D_{\mathrm{KS}} > 0.12$):** Structural breakdown; trips the VSM Algedonic Channel and forces fallback.
    Red,
}

/// Basel III FRTB MAR33 Profit & Loss Attribution Test (`PLAT` — Spearman rank correlation $r_s$
/// and two-sample Kolmogorov-Smirnov statistic $D_{\mathrm{KS}}$ between Risk-Theoretical Loss `RTPL`
/// and Hypothetical Realized Loss `HPL`).
#[derive(Debug, Clone, PartialEq)]
pub struct ProfitLossAttributionTest {
    /// Spearman rank correlation $r_s \in [-1, 1]$ between `RTPL` and `HPL`.
    pub spearman_rank_correlation: f64,
    /// Two-sample Kolmogorov-Smirnov distance $D_{\mathrm{KS}} = \sup_x |F_{\mathrm{RTPL}}(x) - F_{\mathrm{HPL}}(x)|$.
    pub kolmogorov_smirnov_distance: f64,
    /// Assigned Basel III MAR33 traffic-light zone (`Green`, `Amber`, or `Red`).
    pub traffic_light_zone: PlatTrafficLightZone,
}

impl ProfitLossAttributionTest {
    /// Evaluates the PLAT attribution test on paired `rtpl` (model-predicted loss/payoff) and `hpl` (realized loss/payoff).
    pub fn evaluate(rtpl: &[f64], hpl: &[f64]) -> Self {
        assert!(
            !rtpl.is_empty() && rtpl.len() == hpl.len(),
            "PLAT requires non-empty equal-length RTPL and HPL slices"
        );
        let r_s = spearman_rank_corr(rtpl, hpl);
        let d_ks = two_sample_ks_distance(rtpl, hpl);
        let zone = if r_s < 0.70 || d_ks > 0.12 {
            PlatTrafficLightZone::Red
        } else if r_s > 0.80 && d_ks < 0.09 {
            PlatTrafficLightZone::Green
        } else {
            PlatTrafficLightZone::Amber
        };
        Self {
            spearman_rank_correlation: r_s,
            kolmogorov_smirnov_distance: d_ks,
            traffic_light_zone: zone,
        }
    }
}

fn average_ranks(xs: &[f64]) -> Vec<f64> {
    let n = xs.len();
    let mut indexed: Vec<(usize, f64)> = xs.iter().copied().enumerate().collect();
    indexed.sort_by(|a, b| a.1.total_cmp(&b.1));
    let mut ranks = vec![0.0; n];
    let mut i = 0;
    while i < n {
        let mut j = i + 1;
        while j < n && (indexed[j].1 - indexed[i].1).abs() <= 1e-12 {
            j += 1;
        }
        let avg_rank = 0.5 * ((i + 1 + j) as f64);
        for k in i..j {
            ranks[indexed[k].0] = avg_rank;
        }
        i = j;
    }
    ranks
}

fn spearman_rank_corr(x: &[f64], y: &[f64]) -> f64 {
    let rx = average_ranks(x);
    let ry = average_ranks(y);
    let mx = stochology_core::mean(&rx);
    let my = stochology_core::mean(&ry);
    let mut num = 0.0;
    let mut dx2 = 0.0;
    let mut dy2 = 0.0;
    for (&a, &b) in rx.iter().zip(ry.iter()) {
        num += (a - mx) * (b - my);
        dx2 += (a - mx).powi(2);
        dy2 += (b - my).powi(2);
    }
    let denom = (dx2 * dy2).sqrt();
    if denom < 1e-12 {
        0.0
    } else {
        (num / denom).clamp(-1.0, 1.0)
    }
}

fn two_sample_ks_distance(x: &[f64], y: &[f64]) -> f64 {
    let mut sx = x.to_vec();
    let mut sy = y.to_vec();
    sx.sort_by(|a, b| a.total_cmp(b));
    sy.sort_by(|a, b| a.total_cmp(b));
    let nx = sx.len() as f64;
    let ny = sy.len() as f64;
    let mut i = 0usize;
    let mut j = 0usize;
    let mut max_d = 0.0_f64;
    while i < sx.len() && j < sy.len() {
        let v = sx[i].min(sy[j]);
        while i < sx.len() && sx[i] <= v {
            i += 1;
        }
        while j < sy.len() && sy[j] <= v {
            j += 1;
        }
        let d = ((i as f64) / nx - (j as f64) / ny).abs();
        if d > max_d {
            max_d = d;
        }
    }
    max_d
}

/// Criterion of Evaluated Competence (*Critério de Competência Avaliada*):
/// Audits whether an operator or autonomous model demonstrates genuine stochastic competence (**Telos**)
/// rather than unmeasured luck (**Skopos**).
#[derive(Debug, Clone, PartialEq)]
pub struct EvaluatedCompetenceCriterion {
    pub rel_corp_miscalibration: f64,
    pub res_corp_resolution: f64,
    pub kahneman_judgment_noise_sd: f64,
    pub plat_zone: PlatTrafficLightZone,
    pub competence_verified: bool,
}

impl EvaluatedCompetenceCriterion {
    pub fn evaluate(
        rel_corp_miscalibration: f64,
        res_corp_resolution: f64,
        kahneman_judgment_noise_sd: f64,
        plat_zone: PlatTrafficLightZone,
    ) -> Self {
        let competence_verified = rel_corp_miscalibration <= 0.015
            && res_corp_resolution >= 0.010
            && kahneman_judgment_noise_sd <= 0.10
            && plat_zone != PlatTrafficLightZone::Red;
        Self {
            rel_corp_miscalibration,
            res_corp_resolution,
            kahneman_judgment_noise_sd,
            plat_zone,
            competence_verified,
        }
    }
}

/// Predetermined Change Control Plan (`PCCP`, FDA AI/ML SaMD Lifecycle & Basel III Governance Contract):
///
/// Pre-specifies the allowed adaptation region (Data Modification Protocol + Re-training Objective +
/// Performance Evaluation Protocol) and couples Ville's $e$-process ($M_t \ge 1/\alpha$) and the `PLAT`
/// traffic-light test to the VSM Algedonic Channel (*"not measured, not executed"*), triggering an
/// automatic rollback to the sealed baseline when any boundary is breached.
#[derive(Debug, Clone, PartialEq)]
pub struct PredeterminedChangeControlPlan {
    pub plan_id: String,
    pub max_allowed_parameter_l2_drift: f64,
    pub observed_parameter_l2_drift: f64,
    pub sequential_e_process_value: f64,
    pub ville_alarm_threshold_inv_alpha: f64,
    pub plat_result: ProfitLossAttributionTest,
    pub competence_criterion: EvaluatedCompetenceCriterion,
    /// VSM Algedonic Channel rule: *"not measured, not executed"* (`true` blocks unmeasured updates).
    pub algedonic_not_measured_not_executed: bool,
    /// True if the PCCP triggered an automatic rollback to the last sealed baseline.
    pub automatic_rollback_triggered: bool,
    /// True if the candidate update is approved within the pre-registered PCCP envelope.
    pub update_approved: bool,
}

impl PredeterminedChangeControlPlan {
    #[allow(clippy::too_many_arguments)]
    pub fn evaluate_update(
        plan_id: &str,
        max_allowed_parameter_l2_drift: f64,
        observed_parameter_l2_drift: f64,
        sequential_e_process_value: f64,
        alpha: f64,
        rtpl: &[f64],
        hpl: &[f64],
        rel_corp: f64,
        res_corp: f64,
        judgment_noise_sd: f64,
        telemetry_measured: bool,
    ) -> Self {
        let ville_alarm_threshold_inv_alpha = 1.0 / alpha.clamp(1e-6, 0.5);
        let plat_result = ProfitLossAttributionTest::evaluate(rtpl, hpl);
        let competence_criterion = EvaluatedCompetenceCriterion::evaluate(
            rel_corp,
            res_corp,
            judgment_noise_sd,
            plat_result.traffic_light_zone,
        );
        let algedonic_not_measured_not_executed = !telemetry_measured;
        let boundary_breached = !telemetry_measured
            || observed_parameter_l2_drift > max_allowed_parameter_l2_drift
            || sequential_e_process_value >= ville_alarm_threshold_inv_alpha
            || plat_result.traffic_light_zone == PlatTrafficLightZone::Red
            || !competence_criterion.competence_verified;

        Self {
            plan_id: plan_id.to_string(),
            max_allowed_parameter_l2_drift,
            observed_parameter_l2_drift,
            sequential_e_process_value,
            ville_alarm_threshold_inv_alpha,
            plat_result,
            competence_criterion,
            algedonic_not_measured_not_executed,
            automatic_rollback_triggered: boundary_breached,
            update_approved: !boundary_breached,
        }
    }
}

/// Statutory Regulatory Compliance Gate (`RegulatoryComplianceAudit` — EU AI Act Regulation (EU) 2024/1689
/// High-Risk Annex III Articles 9, 10, 14, 15 & Brazilian LGPD Law No. 13.709/2018 Article 20):
///
/// Maps qualitative legal mandates to quantitative, falsifiable Stochology invariants:
/// - **EU AI Act Art. 9 (Risk Management System):** Non-zero Info-Gap robustness horizon $\hat{\alpha}(q, r_c) > 0$ and approved Sniedovich Wald Maximin floor.
/// - **EU AI Act Art. 10 & LGPD Art. 6 III (Data Governance & Minimization):** Bounded Meng `DDI`, explicit Manski/Lee non-response bounds, Moulton-Campbell $n_{\mathrm{eff}}(p) \ge n_{\min}$, and mapped Markov Blanket without Berkson colliders.
/// - **EU AI Act Art. 14 & LGPD Art. 20 (Effective Human Oversight & Right to Explanation):** Shift burst cognitive load $\le 10\text{ bit/s}$ (`AlertFatigueAudit`), Turing deciban weight $W \ge +10\text{ dB}$, and integer Gigerenzer natural-frequency explanation.
/// - **EU AI Act Art. 15 & Chouldechova/KMR ($\Phi_4$) (Accuracy, Robustness & Non-Discrimination):** Isotonic $\mathrm{REL}_{\mathrm{CORP}} \le 0.02$, active `PCCP`/`PLAT` Green/Amber zone, and audited Chouldechova error-bearer declaration.
#[derive(Debug, Clone, PartialEq)]
pub struct RegulatoryComplianceAudit {
    /// EU AI Act Art. 9 (Risk Management via Info-Gap $\hat{\alpha} > 0$ + Sniedovich Maximin floor).
    pub eu_ai_act_art9_risk_management_ok: bool,
    /// EU AI Act Art. 10 & LGPD Art. 6 III (Data Governance via Meng/Manski/Lee + $n_{\mathrm{eff}}(p)$ + Markov Blanket minimization).
    pub eu_ai_act_art10_lgpd_minimization_ok: bool,
    /// EU AI Act Art. 14 & LGPD Art. 20 (Effective Human Oversight $\le 10\text{ bit/s}$ + Gigerenzer natural-frequency explanation).
    pub eu_ai_act_art14_lgpd_art20_human_oversight_ok: bool,
    /// EU AI Act Art. 15 & $\Phi_4$ (Calibration $\mathrm{REL}_{\mathrm{CORP}} \le 0.02$ + `PCCP`/`PLAT` + Chouldechova audit).
    pub eu_ai_act_art15_robustness_fairness_ok: bool,
    /// True if all four statutory pillars pass simultaneously.
    pub all_statutory_requirements_approved: bool,
}

impl RegulatoryComplianceAudit {
    /// Evaluates EU AI Act (Arts. 9, 10, 14, 15) and LGPD (Arts. 6 III, 20) compliance from verified operational metrics.
    #[allow(clippy::too_many_arguments)]
    pub fn evaluate(
        info_gap_alpha_hat: f64,
        sniedovich_approved: bool,
        meng_bounds_and_markov_blanket_ok: bool,
        effective_tail_n_eff: f64,
        human_oversight_bits_per_sec: f64,
        turing_decibans: f64,
        natural_frequency_explanation_attached: bool,
        rel_corp_miscalibration: f64,
        pccp_approved: bool,
        chouldechova_audited: bool,
    ) -> Self {
        let art9 = info_gap_alpha_hat > 0.0 && sniedovich_approved;
        let art10 = meng_bounds_and_markov_blanket_ok && effective_tail_n_eff >= 100.0;
        let art14 = human_oversight_bits_per_sec <= 10.0
            && turing_decibans >= 10.0
            && natural_frequency_explanation_attached;
        let art15 = rel_corp_miscalibration <= 0.02 && pccp_approved && chouldechova_audited;
        Self {
            eu_ai_act_art9_risk_management_ok: art9,
            eu_ai_act_art10_lgpd_minimization_ok: art10,
            eu_ai_act_art14_lgpd_art20_human_oversight_ok: art14,
            eu_ai_act_art15_robustness_fairness_ok: art15,
            all_statutory_requirements_approved: art9 && art10 && art14 && art15,
        }
    }
}

/// Bridge $L_2 \leftrightarrow L_3$ Cloud API vs. Private Local Deployment (`LoRA / QLoRA`) Architecture Audit
/// (`CloudLocalLoraArchitectureAudit`):
///
/// Couples two core engineering decisions from *Estrategista* (Week 4: *Unit Economics & API vs. Local Duel*)
/// and *Cientista Sábio* (Weeks 12 & 19–20: *Fine-Tuning & `LoRA / QLoRA` Private Infrastructure*):
/// 1. **Stochastic Unit Economics & Tailored Base-Surge (`TBS`) vs. Naive Break-Even:**
///    Deterministic break-even $V_{\text{naive}}^* = C_{\text{fixed}} / (c_{\text{API}} - c_{\text{local}})$
///    ignores Kingman queueing congestion ($\frac{u}{1-u}\frac{c_a^2+c_s^2}{2}$) when local GPU utilization
///    $u \to 1$. Serving base volume at $u_{\text{base}} \le 0.78$ locally and routing burst surges to API
///    (`TBS`) strictly dominates both pure-API and overloaded pure-local deployment.
/// 2. **Eckart-Young-Mirsky Spectral Truncation & Gram Effective Dimension for `LoRA` ($\Delta W = BA$):**
///    Computes the Gram effective dimension $d_{\mathrm{eff}}(G) = \frac{(\sum_i \sigma_i^2)^2}{\sum_i \sigma_i^4}$
///    of the task update singular spectrum $\sigma_1 \ge \dots \ge \sigma_d$, the relative Frobenius truncation
///    error $\varepsilon_{\mathrm{LoRA}}(r) = \frac{\sum_{i>r}\sigma_i^2}{\sum_{i=1}^d \sigma_i^2}$, and verifies
///    the exact Pythagorean energy partition $\sum_{i\le r}\sigma_i^2 + \sum_{i>r}\sigma_i^2 = \|\Delta W\|_F^2$.
#[derive(Debug, Clone, PartialEq)]
pub struct CloudLocalLoraArchitectureAudit {
    /// Naive deterministic break-even token volume (ignoring queueing delay).
    pub naive_break_even_volume: f64,
    /// Total monthly cost under pure Cloud API billing.
    pub pure_api_total_cost: f64,
    /// Total monthly cost (CapEx + OpEx + SLA congestion penalty) under overloaded pure local deployment ($u = 0.96$).
    pub overloaded_pure_local_total_cost: f64,
    /// Total monthly cost under Tailored Base-Surge (`TBS`) hybrid local + API spillover routing.
    pub tbs_hybrid_total_cost: f64,
    /// Gram effective dimension $d_{\mathrm{eff}}(G) = \frac{(\mathrm{tr}\,G)^2}{\|G\|_F^2}$ of the task update spectrum.
    pub gram_effective_dimension_d_eff: f64,
    /// Relative Frobenius energy retained by the chosen `LoRA` rank $r \ge \lceil d_{\mathrm{eff}}\rceil$ vs. rank-1 truncation.
    pub lora_retained_energy_ratio: f64,
    pub rank1_retained_energy_ratio: f64,
    /// Exact Eckart-Young Pythagorean energy identity residual $|E_{\le r} + E_{> r} - \|\Delta W\|_F^2|$.
    pub eckart_young_energy_identity_error: f64,
    /// Whether `TBS` hybrid routing beats both pure-API and overloaded pure-local cost, and `LoRA` rank $r$
    /// retains $\ge 95\%$ of the task update Frobenius energy.
    pub architecture_and_lora_approved: bool,
}

impl CloudLocalLoraArchitectureAudit {
    /// Evaluates Cloud API vs. Local GPU `LoRA` unit economics and spectral truncation at rank `lora_rank`.
    #[allow(clippy::too_many_arguments)]
    pub fn evaluate(
        monthly_token_volume_millions: f64,
        local_fixed_monthly_cost: f64,
        local_marginal_cost_per_million: f64,
        api_cost_per_million: f64,
        burst_cv_squared_sum: f64,
        sla_delay_penalty_scale: f64,
        task_singular_values: &[f64],
        lora_rank: usize,
    ) -> Self {
        assert!(
            monthly_token_volume_millions > 0.0
                && api_cost_per_million > local_marginal_cost_per_million
                && !task_singular_values.is_empty()
                && lora_rank > 0
                && lora_rank <= task_singular_values.len(),
            "CloudLocalLoraArchitectureAudit requires valid unit economics and non-empty singular spectrum"
        );
        let unit_saving = (api_cost_per_million - local_marginal_cost_per_million).max(1e-9);
        let naive_break_even_volume = local_fixed_monthly_cost / unit_saving;
        let pure_api_total_cost = monthly_token_volume_millions * api_cost_per_million;

        // Overloaded pure-local deployment running at u = 0.96 suffers Kingman VUT queue blowup
        let u_overloaded = 0.96;
        let kingman_overloaded =
            (u_overloaded / (1.0 - u_overloaded)) * (0.5 * burst_cv_squared_sum);
        let overloaded_pure_local_total_cost = local_fixed_monthly_cost
            + monthly_token_volume_millions * local_marginal_cost_per_million
            + sla_delay_penalty_scale * kingman_overloaded;

        // Tailored Base-Surge (TBS): 78% base load on local QLoRA server (u_base = 0.75) + 22% burst surge spilled to API
        let base_share = 0.78;
        let u_base = 0.75;
        let kingman_base = (u_base / (1.0 - u_base)) * (0.5 * burst_cv_squared_sum);
        let tbs_hybrid_total_cost = local_fixed_monthly_cost
            + (monthly_token_volume_millions * base_share) * local_marginal_cost_per_million
            + (monthly_token_volume_millions * (1.0 - base_share)) * api_cost_per_million
            + sla_delay_penalty_scale * kingman_base;

        let energies: Vec<f64> = task_singular_values.iter().map(|&s| s * s).collect();
        let total_energy: f64 = energies.iter().sum();
        let sum_sq_energy: f64 = energies.iter().map(|&e| e * e).sum();
        let gram_effective_dimension_d_eff =
            (total_energy * total_energy) / sum_sq_energy.max(1e-15);

        let energy_le_r: f64 = energies.iter().take(lora_rank).sum();
        let energy_gt_r: f64 = energies.iter().skip(lora_rank).sum();
        let eckart_young_energy_identity_error = ((energy_le_r + energy_gt_r) - total_energy).abs();
        let lora_retained_energy_ratio = energy_le_r / total_energy.max(1e-15);
        let rank1_retained_energy_ratio = energies[0] / total_energy.max(1e-15);

        let approved = tbs_hybrid_total_cost < pure_api_total_cost
            && tbs_hybrid_total_cost < overloaded_pure_local_total_cost
            && lora_retained_energy_ratio >= 0.95
            && lora_retained_energy_ratio > rank1_retained_energy_ratio + 0.30
            && eckart_young_energy_identity_error < 1e-12;

        Self {
            naive_break_even_volume,
            pure_api_total_cost,
            overloaded_pure_local_total_cost,
            tbs_hybrid_total_cost,
            gram_effective_dimension_d_eff,
            lora_retained_energy_ratio,
            rank1_retained_energy_ratio,
            eckart_young_energy_identity_error,
            architecture_and_lora_approved: approved,
        }
    }

    /// Canonical Cloud API vs. Local `QLoRA` architecture benchmark.
    pub fn canonical_benchmark() -> Self {
        let spectrum = [4.0, 2.8, 1.9, 1.2, 0.45, 0.25, 0.15, 0.08];
        Self::evaluate(1_200.0, 2_400.0, 0.60, 4.50, 3.2, 140.0, &spectrum, 4)
    }
}

#[cfg(test)]
mod tests {
    use super::*;
    use stochology_core::Rng;

    #[test]
    fn covariate_drift_extra_wcp_recovers_tilt_and_lei_candes_bound() {
        let mut rng = Rng::new(2026);
        let x_p: Vec<f64> = (0..500).map(|_| rng.normal(0.0, 1.0)).collect();
        let x_q: Vec<f64> = (0..500).map(|_| rng.normal(0.45, 1.0)).collect();
        let scores: Vec<f64> = x_p.iter().map(|&x| 0.2 + 0.1 * x.abs()).collect();
        let res = fit_covariate_drift_extra_wcp(&x_p, &x_q, &scores, None, 0.01, 0.10);
        assert!(res.estimated_beta > 0.25 && res.estimated_beta < 0.65);
        assert!(
            res.total_variation_distance_d_tv > 0.0 && res.total_variation_distance_d_tv < 0.15
        );
        assert!(res.lei_candes_coverage_lower_bound < res.nominal_level_one_minus_alpha);
        assert!(res.lei_candes_coverage_lower_bound > 0.75);
    }

    #[test]
    fn four_label_shift_estimators_converge_toward_new_target_prior() {
        // Source prior p1 = 0.10, TPR = 0.85, FPR = 0.10 -> target prior q1 = 0.35
        // Target predicted positive rate = 0.35 * 0.85 + 0.65 * 0.10 = 0.3625 (72 / 200)
        // Source-calibrated posteriors: P_s(y=1 | y_hat=1) = 0.4857, P_s(y=1 | y_hat=0) = 0.0182
        let mut probs = Vec::with_capacity(200);
        for i in 0..200 {
            if i < 72 {
                probs.push(0.4857);
            } else {
                probs.push(0.0182);
            }
        }
        let diag =
            estimate_label_shift_four_methods(0.10, 0.85, 0.10, &probs, 10.0, 30.0, 17.0, 0.0);
        assert!((diag.target_prior_bbse - 0.3467).abs() < 0.02);
        assert!(diag.target_prior_mlls_sld > 0.25 && diag.target_prior_mlls_sld < 0.45);
        assert!((diag.target_prior_dfm - 0.35).abs() < 1e-9);
        assert!((diag.target_prior_otter - 0.345).abs() < 0.05);
        assert!(diag.confusion_matrix_sigma_min > 0.01);
        assert!(diag.hoffman_constant_kappa > 1.0);
    }

    #[test]
    fn murphy_corp_circuit_breaker_separates_concept_drift_from_label_shift() {
        // Inverted predictions -> RES_CORP = 0 -> trips Concept Drift circuit breaker!
        let p_bad = [0.9, 0.85, 0.15, 0.1];
        let y = [0.0, 0.0, 1.0, 1.0];
        let m_bad = MurphyCorpCircuitBreaker::monitor(&p_bad, &y, 0.05, 0.05, false, false, false);
        assert!(m_bad.circuit_breaker_tripped);
        assert_eq!(
            m_bad.diagnosed_regime,
            DriftRegime::ConceptDriftCircuitBreaker
        );
    }

    #[test]
    fn decile_tv_detects_bimodal_shift_with_matched_moments_and_dfm_is_translation_invariant() {
        let mut rng = Rng::new(2026);
        let x_p: Vec<f64> = (0..400).map(|_| rng.normal(0.0, 1.0)).collect();
        // Symmetric bimodal target (+1 / -1) has mean ~ 0 and variance ~ 1, matching N(0, 1) first two moments
        let x_q_bimodal: Vec<f64> = (0..400)
            .map(|i| if i % 2 == 0 { -1.0 } else { 1.0 })
            .collect();
        let scores: Vec<f64> = x_p.iter().map(|&x| 0.2 + 0.1 * x.abs()).collect();
        let res = fit_covariate_drift_extra_wcp(&x_p, &x_q_bimodal, &scores, None, 0.01, 0.10);
        assert!(res.total_variation_distance_d_tv > 0.15);

        // DFM translation invariance under alpha0 > 0: shifting all feature means by +500 leaves q1_dfm unchanged
        let probs = [0.4857; 72];
        let d1 =
            estimate_label_shift_four_methods(0.10, 0.85, 0.10, &probs, 10.0, 30.0, 16.3, 0.10);
        let d2 =
            estimate_label_shift_four_methods(0.10, 0.85, 0.10, &probs, 510.0, 530.0, 516.3, 0.10);
        assert!((d1.target_prior_dfm - d2.target_prior_dfm).abs() < 1e-12);
        assert!((d1.target_prior_dfm - 0.35).abs() < 1e-9);

        // Online ACI adapts to residual inflation where static conformal coverage drops to 75%
        let cal_scores: Vec<f64> = (1..=200).map(|i| (i as f64) * 0.01).collect();
        let shifted_stream: Vec<f64> = (0..200).map(|i| 1.40 + ((i % 20) as f64) * 0.028).collect();
        let aci =
            AdaptiveConformalInference::evaluate_stream(&cal_scores, &shifted_stream, 0.10, 0.02);
        assert!(aci.empirical_coverage_aci > aci.empirical_coverage_static + 0.10);
        assert!((aci.empirical_coverage_aci - 0.90).abs() < 0.04);

        // PCCP & PLAT traffic-light verification
        let rtpl: Vec<f64> = (0..100).map(|i| (i as f64) * 0.5).collect();
        let hpl_green: Vec<f64> = (0..100).map(|i| (i as f64) * 0.5 + 0.2).collect();
        let hpl_red: Vec<f64> = (0..100).map(|i| ((99 - i) as f64) * 0.5 + 15.0).collect();

        let pccp_ok = PredeterminedChangeControlPlan::evaluate_update(
            "PCCP-2026-GREEN",
            0.25,
            0.08,
            1.4,
            0.05,
            &rtpl,
            &hpl_green,
            0.004,
            0.035,
            0.05,
            true,
        );
        assert_eq!(
            pccp_ok.plat_result.traffic_light_zone,
            PlatTrafficLightZone::Green
        );
        assert!(pccp_ok.update_approved && !pccp_ok.automatic_rollback_triggered);

        let pccp_red = PredeterminedChangeControlPlan::evaluate_update(
            "PCCP-2026-RED",
            0.25,
            0.08,
            25.0,
            0.05,
            &rtpl,
            &hpl_red,
            0.004,
            0.035,
            0.05,
            true,
        );
        assert_eq!(
            pccp_red.plat_result.traffic_light_zone,
            PlatTrafficLightZone::Red
        );
        assert!(pccp_red.automatic_rollback_triggered && !pccp_red.update_approved);

        let arch = CloudLocalLoraArchitectureAudit::canonical_benchmark();
        assert!(arch.architecture_and_lora_approved);
        assert!(arch.tbs_hybrid_total_cost < arch.pure_api_total_cost);
        assert!(arch.tbs_hybrid_total_cost < arch.overloaded_pure_local_total_cost);
        assert!(arch.lora_retained_energy_ratio > 0.98);
        assert!(arch.eckart_young_energy_identity_error < 1e-12);
    }
}

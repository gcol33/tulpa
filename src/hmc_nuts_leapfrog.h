// hmc_nuts_leapfrog.h
// Fragment of hmc_nuts_sampler.cpp. Included from the umbrella
// translation unit inside namespace tulpa_hmc; do NOT add a
// namespace wrapper here; do not list this file in the package SRCS —
// it is not a standalone translation unit.
// Leapfrog integrator + initial-step-size helper.
#ifndef TULPA_HMC_NUTS_LEAPFROG_H
#define TULPA_HMC_NUTS_LEAPFROG_H

// =====================================================================
// Leapfrog integrator
// =====================================================================

// Unified leapfrog step: identity mass when inv_mass is nullptr
LeapfrogResult leapfrog_step(
    const std::vector<double>& q,
    const std::vector<double>& p,
    double epsilon,
    const ModelData& data,
    const ParamLayout& layout,
    const double* inv_mass
) {
  int n = q.size();
  LeapfrogResult result;
  result.q = q;
  result.p = p;
  result.divergent = false;

  std::vector<double> grad(n);

  // Half step for momentum
  compute_gradient(result.q, data, layout, grad);
  for (int i = 0; i < n; i++) {
    result.p[i] += 0.5 * epsilon * grad[i];
  }

  // Full step for position (scaled by inverse mass if provided)
  if (inv_mass) {
    for (int i = 0; i < n; i++) {
      result.q[i] += epsilon * inv_mass[i] * result.p[i];
    }
  } else {
    for (int i = 0; i < n; i++) {
      result.q[i] += epsilon * result.p[i];
    }
  }

  // Half step for momentum (fused gradient + log_prob)
  compute_gradient(result.q, data, layout, grad, &result.log_prob);
  for (int i = 0; i < n; i++) {
    result.p[i] += 0.5 * epsilon * grad[i];
  }

  if (!std::isfinite(result.log_prob)) {
    result.divergent = true;
  }

  for (int i = 0; i < n; i++) {
    if (std::abs(result.q[i]) > 1e10 || !std::isfinite(result.q[i])) {
      result.divergent = true;
      break;
    }
  }

  return result;
}

// =====================================================================
// Find reasonable initial step size
// =====================================================================

// Compute diagonal mass matrix from gradient magnitudes
std::vector<double> compute_diagonal_mass(
    const std::vector<double>& q,
    const ModelData& data,
    const ParamLayout& layout
) {
  int n = q.size();
  std::vector<double> grad(n);
  compute_gradient(q, data, layout, grad);

  std::vector<double> mass(n);
  for (int i = 0; i < n; i++) {
    double abs_grad = std::abs(grad[i]);
    mass[i] = std::max(1.0, std::min(abs_grad, 1000.0));
  }

  return mass;
}

#endif  // TULPA_HMC_NUTS_LEAPFROG_H

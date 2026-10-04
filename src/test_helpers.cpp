// test_helpers.cpp
// Rcpp wrappers to expose internal C++ functions for unit testing

#include <Rcpp.h>
#include <cmath>
#include <vector>
#include <random>
#include "autodiff.h"
#include "laplace_core.h"
#include "pg_binomial.h"
#include "omp_sum.h"

using namespace Rcpp;

// ---------------------------------------------------------------------------
// Leapfrog integrator (standalone version for testing)
// ---------------------------------------------------------------------------

// Simple quadratic potential for testing: U(q) = 0.5 * sum(q^2)
// Gradient: dU/dq = q
// [[Rcpp::export]]
List cpp_test_leapfrog(
    NumericVector q_init,
    NumericVector p_init,
    double epsilon,
    int L
) {
  int d = q_init.size();
  std::vector<double> q(q_init.begin(), q_init.end());
  std::vector<double> p(p_init.begin(), p_init.end());

  // Leapfrog integration with quadratic potential U(q) = 0.5 * sum(q^2)
  // Gradient dU/dq = q

  // Half step for momentum
  for (int i = 0; i < d; i++) {
    p[i] = p[i] - 0.5 * epsilon * q[i];
  }

  // Full steps
  for (int step = 0; step < L - 1; step++) {
    // Full step for position
    for (int i = 0; i < d; i++) {
      q[i] = q[i] + epsilon * p[i];
    }
    // Full step for momentum
    for (int i = 0; i < d; i++) {
      p[i] = p[i] - epsilon * q[i];
    }
  }

  // Final full step for position
  for (int i = 0; i < d; i++) {
    q[i] = q[i] + epsilon * p[i];
  }

  // Half step for momentum
  for (int i = 0; i < d; i++) {
    p[i] = p[i] - 0.5 * epsilon * q[i];
  }

  return List::create(
    Named("q") = NumericVector(q.begin(), q.end()),
    Named("p") = NumericVector(p.begin(), p.end())
  );
}

// ---------------------------------------------------------------------------
// Hamiltonian computation for testing
// ---------------------------------------------------------------------------

// [[Rcpp::export]]
double cpp_test_hamiltonian(NumericVector q, NumericVector p) {
  // H(q, p) = U(q) + K(p) = 0.5 * sum(q^2) + 0.5 * sum(p^2)
  double H = 0.0;
  for (int i = 0; i < q.size(); i++) {
    H += 0.5 * q[i] * q[i] + 0.5 * p[i] * p[i];
  }
  return H;
}

// ---------------------------------------------------------------------------
// Log-sum-exp (numerically stable)
// ---------------------------------------------------------------------------

// [[Rcpp::export]]
double cpp_test_log_sum_exp(NumericVector log_vals) {
  if (log_vals.size() == 0) return R_NegInf;

  double max_val = *std::max_element(log_vals.begin(), log_vals.end());
  if (max_val == R_NegInf) return R_NegInf;

  double sum_exp = 0.0;
  for (int i = 0; i < log_vals.size(); i++) {
    sum_exp += std::exp(log_vals[i] - max_val);
  }

  return max_val + std::log(sum_exp);
}

// ---------------------------------------------------------------------------
// Softmax (numerically stable)
// ---------------------------------------------------------------------------

// [[Rcpp::export]]
NumericVector cpp_test_softmax(NumericVector x) {
  double max_val = *std::max_element(x.begin(), x.end());
  NumericVector result(x.size());
  double sum_exp = 0.0;

  for (int i = 0; i < x.size(); i++) {
    result[i] = std::exp(x[i] - max_val);
    sum_exp += result[i];
  }

  for (int i = 0; i < x.size(); i++) {
    result[i] /= sum_exp;
  }

  return result;
}

// ---------------------------------------------------------------------------
// Inverse logit (sigmoid)
// ---------------------------------------------------------------------------

// [[Rcpp::export]]
NumericVector cpp_test_inv_logit(NumericVector x) {
  NumericVector result(x.size());
  for (int i = 0; i < x.size(); i++) {
    result[i] = 1.0 / (1.0 + std::exp(-x[i]));
  }
  return result;
}

// ---------------------------------------------------------------------------
// Log-gamma function wrapper
// ---------------------------------------------------------------------------

// [[Rcpp::export]]
double cpp_test_lgamma(double x) {
  return std::lgamma(x);
}

// ---------------------------------------------------------------------------
// Poisson log-likelihood
// ---------------------------------------------------------------------------

// [[Rcpp::export]]
double cpp_test_poisson_loglik(IntegerVector y, NumericVector lambda) {
  double ll = 0.0;
  for (int i = 0; i < y.size(); i++) {
    if (lambda[i] > 0) {
      ll += y[i] * std::log(lambda[i]) - lambda[i] - std::lgamma(y[i] + 1);
    } else if (y[i] > 0) {
      return R_NegInf;
    }
  }
  return ll;
}

// ---------------------------------------------------------------------------
// Binomial log-likelihood
// ---------------------------------------------------------------------------

// [[Rcpp::export]]
double cpp_test_binomial_loglik(IntegerVector y, IntegerVector n, NumericVector p) {
  double ll = 0.0;
  for (int i = 0; i < y.size(); i++) {
    if (p[i] > 0 && p[i] < 1) {
      ll += y[i] * std::log(p[i]) + (n[i] - y[i]) * std::log(1 - p[i]);
      ll += std::lgamma(n[i] + 1) - std::lgamma(y[i] + 1) - std::lgamma(n[i] - y[i] + 1);
    } else if ((p[i] <= 0 && y[i] > 0) || (p[i] >= 1 && y[i] < n[i])) {
      return R_NegInf;
    }
  }
  return ll;
}

// ---------------------------------------------------------------------------
// Negative binomial log-likelihood
// ---------------------------------------------------------------------------

// [[Rcpp::export]]
double cpp_test_negbin_loglik(IntegerVector y, NumericVector mu, double phi) {
  double ll = 0.0;
  for (int i = 0; i < y.size(); i++) {
    double r = phi;  // size parameter
    double p = r / (r + mu[i]);  // success probability
    ll += std::lgamma(y[i] + r) - std::lgamma(r) - std::lgamma(y[i] + 1);
    ll += r * std::log(p) + y[i] * std::log(1 - p);
  }
  return ll;
}

// ---------------------------------------------------------------------------
// Normal log-likelihood
// ---------------------------------------------------------------------------

// [[Rcpp::export]]
double cpp_test_normal_loglik(NumericVector y, NumericVector mu, double sigma) {
  double ll = 0.0;
  double tau = 1.0 / (sigma * sigma);
  for (int i = 0; i < y.size(); i++) {
    double resid = y[i] - mu[i];
    ll += -0.5 * std::log(2 * M_PI) - std::log(sigma) - 0.5 * tau * resid * resid;
  }
  return ll;
}

// ---------------------------------------------------------------------------
// Cholesky decomposition (for testing covariance matrices)
// ---------------------------------------------------------------------------

// [[Rcpp::export]]
NumericMatrix cpp_test_cholesky(NumericMatrix A) {
  int n = A.nrow();
  NumericMatrix L(n, n);

  for (int i = 0; i < n; i++) {
    for (int j = 0; j <= i; j++) {
      double sum = 0.0;
      for (int k = 0; k < j; k++) {
        sum += L(i, k) * L(j, k);
      }
      if (i == j) {
        L(i, j) = std::sqrt(A(i, i) - sum);
      } else {
        L(i, j) = (A(i, j) - sum) / L(j, j);
      }
    }
  }

  return L;
}

// ---------------------------------------------------------------------------
// Matrix-vector multiplication
// ---------------------------------------------------------------------------

// [[Rcpp::export]]
NumericVector cpp_test_matvec(NumericMatrix A, NumericVector x) {
  int n = A.nrow();
  int m = A.ncol();
  NumericVector result(n);

  for (int i = 0; i < n; i++) {
    result[i] = 0.0;
    for (int j = 0; j < m; j++) {
      result[i] += A(i, j) * x[j];
    }
  }

  return result;
}

// ---------------------------------------------------------------------------
// Autodiff tests - test the actual autodiff.h implementation
// ---------------------------------------------------------------------------

using namespace ratiod::ad;

// [[Rcpp::export]]
List cpp_test_autodiff_gradient(NumericVector x_vals) {
  // Test gradient computation for f(x) = sum(x^2)
  // Gradient should be 2*x
  init_tape();

  int n = x_vals.size();
  std::vector<Var> x(n);

  // Initialize with values
  for (int i = 0; i < n; i++) {
    x[i] = Var(x_vals[i]);
  }

  // Compute f(x) = sum(x^2)
  Var result = Var(0.0);
  for (int i = 0; i < n; i++) {
    result = result + x[i] * x[i];
  }

  // Backward pass
  result.backward();

  // Extract gradients
  NumericVector grads(n);
  for (int i = 0; i < n; i++) {
    grads[i] = x[i].adj();
  }

  double value = result.val();
  clear_tape();

  return List::create(
    Named("value") = value,
    Named("gradient") = grads
  );
}

// [[Rcpp::export]]
List cpp_test_autodiff_exp_chain(double x_val) {
  // Test chain rule: f(x) = exp(x^2)
  // f'(x) = 2x * exp(x^2)
  init_tape();

  Var x(x_val);
  Var x_sq = x * x;
  Var result = ratiod::ad::exp(x_sq);

  result.backward();

  double expected_grad = 2.0 * x_val * std::exp(x_val * x_val);
  double grad = x.adj();
  double value = result.val();

  clear_tape();

  return List::create(
    Named("value") = value,
    Named("gradient") = grad,
    Named("expected_gradient") = expected_grad
  );
}

// [[Rcpp::export]]
List cpp_test_autodiff_log_likelihood(IntegerVector y, NumericVector eta) {
  // Test Poisson log-likelihood gradient w.r.t. linear predictor
  // ll = sum(y * eta - exp(eta))
  // dll/deta = y - exp(eta)
  init_tape();

  int n = y.size();
  std::vector<Var> eta_ad(n);

  for (int i = 0; i < n; i++) {
    eta_ad[i] = Var(eta[i]);
  }

  Var ll = Var(0.0);
  for (int i = 0; i < n; i++) {
    ll = ll + Var((double)y[i]) * eta_ad[i] - ratiod::ad::exp(eta_ad[i]);
  }

  ll.backward();

  NumericVector grads(n);
  NumericVector expected_grads(n);
  for (int i = 0; i < n; i++) {
    grads[i] = eta_ad[i].adj();
    expected_grads[i] = y[i] - std::exp(eta[i]);
  }

  double value = ll.val();
  clear_tape();

  return List::create(
    Named("value") = value,
    Named("gradient") = grads,
    Named("expected_gradient") = expected_grads
  );
}

// [[Rcpp::export]]
List cpp_test_autodiff_division(double a_val, double b_val) {
  // Test division: f(a, b) = a / b
  // df/da = 1/b, df/db = -a/b^2
  init_tape();

  Var a(a_val);
  Var b(b_val);

  Var result = a / b;

  result.backward();

  double value = result.val();
  double grad_a = a.adj();
  double grad_b = b.adj();

  clear_tape();

  return List::create(
    Named("value") = value,
    Named("grad_a") = grad_a,
    Named("grad_b") = grad_b,
    Named("expected_grad_a") = 1.0 / b_val,
    Named("expected_grad_b") = -a_val / (b_val * b_val)
  );
}

// [[Rcpp::export]]
List cpp_test_autodiff_lgamma(double x_val) {
  // Test lgamma gradient: d/dx lgamma(x) = digamma(x)
  init_tape();

  Var x(x_val);

  Var result = ratiod::ad::lgamma(x);

  result.backward();

  // R's digamma function for comparison
  double expected_grad = R::digamma(x_val);
  double value = result.val();
  double grad = x.adj();

  clear_tape();

  return List::create(
    Named("value") = value,
    Named("gradient") = grad,
    Named("expected_gradient") = expected_grad
  );
}

// [[Rcpp::export]]
List cpp_test_autodiff_softplus(double x_val) {
  // Test softplus: f(x) = log(1 + exp(x))
  // f'(x) = sigmoid(x) = 1 / (1 + exp(-x))
  init_tape();

  Var x(x_val);
  Var result = ratiod::ad::softplus(x);

  result.backward();

  double expected_grad = 1.0 / (1.0 + std::exp(-x_val));
  double value = result.val();
  double grad = x.adj();

  clear_tape();

  return List::create(
    Named("value") = value,
    Named("gradient") = grad,
    Named("expected_gradient") = expected_grad
  );
}

// [[Rcpp::export]]
List cpp_test_autodiff_inv_logit(double x_val) {
  // Test inv_logit (sigmoid): f(x) = 1 / (1 + exp(-x))
  // f'(x) = f(x) * (1 - f(x))
  init_tape();

  Var x(x_val);
  Var result = ratiod::ad::inv_logit(x);

  result.backward();

  double sigmoid_val = 1.0 / (1.0 + std::exp(-x_val));
  double expected_grad = sigmoid_val * (1.0 - sigmoid_val);
  double value = result.val();
  double grad = x.adj();

  clear_tape();

  return List::create(
    Named("value") = value,
    Named("gradient") = grad,
    Named("expected_gradient") = expected_grad
  );
}

// ---------------------------------------------------------------------------
// Autodiff: Additional math functions
// ---------------------------------------------------------------------------

// [[Rcpp::export]]
List cpp_test_autodiff_log(double x_val) {
  // Test log: f(x) = log(x), f'(x) = 1/x
  init_tape();

  Var x(x_val);
  Var result = ratiod::ad::log(x);

  result.backward();

  double value = result.val();
  double grad = x.adj();

  clear_tape();

  return List::create(
    Named("value") = value,
    Named("gradient") = grad,
    Named("expected_gradient") = 1.0 / x_val
  );
}

// [[Rcpp::export]]
List cpp_test_autodiff_sqrt(double x_val) {
  // Test sqrt: f(x) = sqrt(x), f'(x) = 1/(2*sqrt(x))
  init_tape();

  Var x(x_val);
  Var result = ratiod::ad::sqrt(x);

  result.backward();

  double value = result.val();
  double grad = x.adj();

  clear_tape();

  return List::create(
    Named("value") = value,
    Named("gradient") = grad,
    Named("expected_gradient") = 1.0 / (2.0 * std::sqrt(x_val))
  );
}

// [[Rcpp::export]]
List cpp_test_autodiff_pow(double x_val, double p) {
  // Test pow: f(x) = x^p, f'(x) = p * x^(p-1)
  init_tape();

  Var x(x_val);
  Var result = ratiod::ad::pow(x, p);

  result.backward();

  double value = result.val();
  double grad = x.adj();

  clear_tape();

  return List::create(
    Named("value") = value,
    Named("gradient") = grad,
    Named("expected_gradient") = p * std::pow(x_val, p - 1.0)
  );
}

// [[Rcpp::export]]
List cpp_test_autodiff_log1p(double x_val) {
  // Test log1p: f(x) = log(1+x), f'(x) = 1/(1+x)
  init_tape();

  Var x(x_val);
  Var result = ratiod::ad::log1p(x);

  result.backward();

  double value = result.val();
  double grad = x.adj();

  clear_tape();

  return List::create(
    Named("value") = value,
    Named("gradient") = grad,
    Named("expected_gradient") = 1.0 / (1.0 + x_val)
  );
}

// [[Rcpp::export]]
List cpp_test_autodiff_log_sum_exp(double a_val, double b_val) {
  // Test log_sum_exp: f(a,b) = log(exp(a) + exp(b))
  // df/da = exp(a) / (exp(a) + exp(b)) = softmax(a)
  // df/db = exp(b) / (exp(a) + exp(b)) = softmax(b)
  init_tape();

  Var a(a_val);
  Var b(b_val);
  Var result = ratiod::ad::log_sum_exp(a, b);

  result.backward();

  double value = result.val();
  double grad_a = a.adj();
  double grad_b = b.adj();

  // Expected gradients (softmax)
  double max_val = std::max(a_val, b_val);
  double sum_exp = std::exp(a_val - max_val) + std::exp(b_val - max_val);
  double expected_a = std::exp(a_val - max_val) / sum_exp;
  double expected_b = std::exp(b_val - max_val) / sum_exp;

  clear_tape();

  return List::create(
    Named("value") = value,
    Named("grad_a") = grad_a,
    Named("grad_b") = grad_b,
    Named("expected_grad_a") = expected_a,
    Named("expected_grad_b") = expected_b
  );
}

// [[Rcpp::export]]
List cpp_test_autodiff_logit(double x_val) {
  // Test logit: f(x) = log(x/(1-x)), f'(x) = 1/(x*(1-x))
  init_tape();

  Var x(x_val);
  Var result = ratiod::ad::logit(x);

  result.backward();

  double value = result.val();
  double grad = x.adj();

  clear_tape();

  return List::create(
    Named("value") = value,
    Named("gradient") = grad,
    Named("expected_gradient") = 1.0 / (x_val * (1.0 - x_val))
  );
}

// ---------------------------------------------------------------------------
// Autodiff: Compound expressions (test gradient accumulation)
// ---------------------------------------------------------------------------

// [[Rcpp::export]]
List cpp_test_autodiff_negbin_loglik(IntegerVector y, NumericVector mu, double phi) {
  // Test negative binomial log-likelihood gradient
  // ll = sum( lgamma(y + phi) - lgamma(phi) - lgamma(y + 1)
  //           + phi * log(phi/(phi+mu)) + y * log(mu/(phi+mu)) )
  init_tape();

  int n = y.size();
  std::vector<Var> mu_ad(n);
  for (int i = 0; i < n; i++) {
    mu_ad[i] = Var(mu[i]);
  }
  Var phi_ad(phi);

  Var ll = Var(0.0);
  for (int i = 0; i < n; i++) {
    // lgamma terms (y and phi are treated as constants for gradient purposes)
    ll = ll + ratiod::ad::lgamma(Var((double)y[i]) + phi_ad);
    ll = ll - ratiod::ad::lgamma(phi_ad);

    // phi * log(phi/(phi+mu)) + y * log(mu/(phi+mu))
    Var rate = phi_ad + mu_ad[i];
    ll = ll + phi_ad * ratiod::ad::log(phi_ad / rate);
    ll = ll + Var((double)y[i]) * ratiod::ad::log(mu_ad[i] / rate);
  }

  ll.backward();

  NumericVector grads_mu(n);
  for (int i = 0; i < n; i++) {
    grads_mu[i] = mu_ad[i].adj();
  }
  double grad_phi = phi_ad.adj();
  double value = ll.val();

  clear_tape();

  return List::create(
    Named("value") = value,
    Named("gradient_mu") = grads_mu,
    Named("gradient_phi") = grad_phi
  );
}

// ---------------------------------------------------------------------------
// Laplace core likelihood functions (from laplace_core.cpp)
// ---------------------------------------------------------------------------

// [[Rcpp::export]]
List cpp_test_laplace_binomial(int y, int n, double eta) {
  double ll = ratiod::log_lik_binomial(y, n, eta);
  double grad = ratiod::grad_log_lik_binomial(y, n, eta);
  double neg_hess = ratiod::neg_hess_log_lik_binomial(y, n, eta);

  return List::create(
    Named("log_lik") = ll,
    Named("gradient") = grad,
    Named("neg_hessian") = neg_hess
  );
}

// [[Rcpp::export]]
List cpp_test_laplace_negbin(int y, double eta, double phi) {
  double ll = ratiod::log_lik_negbin(y, eta, phi);
  double grad = ratiod::grad_log_lik_negbin(y, eta, phi);
  double neg_hess = ratiod::neg_hess_log_lik_negbin(y, eta, phi);

  return List::create(
    Named("log_lik") = ll,
    Named("gradient") = grad,
    Named("neg_hessian") = neg_hess
  );
}

// [[Rcpp::export]]
List cpp_test_laplace_poisson(int y, double eta) {
  double ll = ratiod::log_lik_poisson(y, eta);
  double grad = ratiod::grad_log_lik_poisson(y, eta);
  double neg_hess = ratiod::neg_hess_log_lik_poisson(y, eta);

  return List::create(
    Named("log_lik") = ll,
    Named("gradient") = grad,
    Named("neg_hessian") = neg_hess
  );
}

// ---------------------------------------------------------------------------
// PG Binomial helper functions (from pg_binomial.cpp)
// ---------------------------------------------------------------------------

// [[Rcpp::export]]
NumericVector cpp_test_pg_update_beta(
    NumericVector kappa,
    NumericVector omega,
    NumericMatrix X,
    NumericVector re_contrib,
    double prior_sd
) {
  return ratiod::update_beta(kappa, omega, X, re_contrib, prior_sd);
}

// [[Rcpp::export]]
NumericVector cpp_test_pg_update_re(
    NumericVector kappa,
    NumericVector omega,
    NumericVector X_beta,
    IntegerVector group,
    int n_groups,
    double sigma_re
) {
  return ratiod::update_re(kappa, omega, X_beta, group, n_groups, sigma_re);
}

// [[Rcpp::export]]
double cpp_test_pg_update_sigma_re(NumericVector re, double scale) {
  return ratiod::update_sigma_re(re, scale);
}

// ---------------------------------------------------------------------------
// linalg_fast.h test wrappers
// ---------------------------------------------------------------------------

#include "linalg_fast.h"

// [[Rcpp::export]]
double cpp_test_dot_product(NumericVector x, NumericVector y) {
  return ratiod_linalg::dot_product(x.begin(), y.begin(), x.size());
}

// [[Rcpp::export]]
double cpp_test_norm_squared(NumericVector x) {
  return ratiod_linalg::norm_squared(x.begin(), x.size());
}

// [[Rcpp::export]]
double cpp_test_vector_sum(NumericVector x) {
  return ratiod_linalg::vector_sum(x.begin(), x.size());
}

// [[Rcpp::export]]
NumericVector cpp_test_axpy(double a, NumericVector x, NumericVector y) {
  NumericVector result = clone(y);
  ratiod_linalg::axpy(a, x.begin(), result.begin(), x.size());
  return result;
}

// [[Rcpp::export]]
NumericVector cpp_test_scale(double a, NumericVector x) {
  NumericVector result = clone(x);
  ratiod_linalg::scale(a, result.begin(), x.size());
  return result;
}

// [[Rcpp::export]]
NumericVector cpp_test_linalg_matvec(NumericMatrix X, NumericVector beta) {
  int N = X.nrow();
  int p = X.ncol();
  std::vector<double> X_flat(N * p);
  for (int i = 0; i < N; i++) {
    for (int j = 0; j < p; j++) {
      X_flat[i * p + j] = X(i, j);
    }
  }
  NumericVector y(N);
  ratiod_linalg::matvec(X_flat.data(), beta.begin(), y.begin(), N, p);
  return y;
}

// [[Rcpp::export]]
NumericVector cpp_test_linalg_matvec_add(NumericMatrix X, NumericVector beta, NumericVector y_init) {
  int N = X.nrow();
  int p = X.ncol();
  std::vector<double> X_flat(N * p);
  for (int i = 0; i < N; i++) {
    for (int j = 0; j < p; j++) {
      X_flat[i * p + j] = X(i, j);
    }
  }
  NumericVector y = clone(y_init);
  ratiod_linalg::matvec_add(X_flat.data(), beta.begin(), y.begin(), N, p);
  return y;
}

// [[Rcpp::export]]
NumericVector cpp_test_linalg_matvec_transpose(NumericMatrix X, NumericVector x) {
  int N = X.nrow();
  int p = X.ncol();
  std::vector<double> X_flat(N * p);
  for (int i = 0; i < N; i++) {
    for (int j = 0; j < p; j++) {
      X_flat[i * p + j] = X(i, j);
    }
  }
  NumericVector y(p);
  ratiod_linalg::matvec_transpose(X_flat.data(), x.begin(), y.begin(), N, p);
  return y;
}

// [[Rcpp::export]]
double cpp_test_sparse_laplacian_quadform(IntegerVector row_ptr, IntegerVector col_idx, NumericVector x) {
  return ratiod_linalg::sparse_laplacian_quadform(row_ptr.begin(), col_idx.begin(), x.begin(), x.size());
}

// [[Rcpp::export]]
double cpp_test_linalg_log_sum_exp(double a, double b) {
  return ratiod_linalg::log_sum_exp(a, b);
}

// [[Rcpp::export]]
double cpp_test_linalg_log_sum_exp_vec(NumericVector x) {
  return ratiod_linalg::log_sum_exp_vec(x.begin(), x.size());
}

// [[Rcpp::export]]
NumericVector cpp_test_softmax_inplace(NumericVector x) {
  NumericVector result = clone(x);
  ratiod_linalg::softmax_inplace(result.begin(), result.size());
  return result;
}

// [[Rcpp::export]]
List cpp_test_compute_linear_predictors(
    NumericMatrix X_num, NumericVector beta_num,
    NumericMatrix X_denom, NumericVector beta_denom,
    int n_threads
) {
  int N = X_num.nrow();
  int p_num = X_num.ncol();
  int p_denom = X_denom.ncol();

  std::vector<double> X_num_flat(N * p_num);
  std::vector<double> X_denom_flat(N * p_denom);

  for (int i = 0; i < N; i++) {
    for (int j = 0; j < p_num; j++) {
      X_num_flat[i * p_num + j] = X_num(i, j);
    }
    for (int j = 0; j < p_denom; j++) {
      X_denom_flat[i * p_denom + j] = X_denom(i, j);
    }
  }

  NumericVector eta_num(N);
  NumericVector eta_denom(N);

  ratiod_linalg::compute_linear_predictors(
    X_num_flat.data(), beta_num.begin(), p_num,
    X_denom_flat.data(), beta_denom.begin(), p_denom,
    eta_num.begin(), eta_denom.begin(), N, n_threads
  );

  return List::create(
    Named("eta_num") = eta_num,
    Named("eta_denom") = eta_denom
  );
}

// ---------------------------------------------------------------------------
// hmc_temporal.h test wrappers
// ---------------------------------------------------------------------------

#include "hmc_temporal.h"
#include "hmc_temporal_multiscale.h"

// [[Rcpp::export]]
double cpp_test_rw1_quadratic_form(NumericVector phi, bool cyclic) {
  return ratiod_temporal::rw1_quadratic_form(phi.begin(), phi.size(), cyclic);
}

// [[Rcpp::export]]
double cpp_test_rw2_quadratic_form(NumericVector phi, bool cyclic) {
  return ratiod_temporal::rw2_quadratic_form(phi.begin(), phi.size(), cyclic);
}

// [[Rcpp::export]]
double cpp_test_ar1_log_density(NumericVector phi, double rho, double tau) {
  return ratiod_temporal::ar1_log_density(phi.begin(), phi.size(), rho, tau);
}

// [[Rcpp::export]]
double cpp_test_temporal_log_prior(
    NumericVector phi,
    std::string type_str,
    double tau,
    double rho,
    bool cyclic
) {
  ratiod_temporal::TemporalType type;
  if (type_str == "rw1") {
    type = ratiod_temporal::TemporalType::RW1;
  } else if (type_str == "rw2") {
    type = ratiod_temporal::TemporalType::RW2;
  } else if (type_str == "ar1") {
    type = ratiod_temporal::TemporalType::AR1;
  } else {
    type = ratiod_temporal::TemporalType::NONE;
  }

  return ratiod_temporal::temporal_log_prior(
    phi.begin(), phi.size(), type, tau, rho, cyclic
  );
}

// [[Rcpp::export]]
double cpp_test_ms_rw_log_lik(NumericVector phi, double sigma2, int order,
                              bool cyclic, bool augment) {
  std::vector<double> v(phi.begin(), phi.end());
  return order == 2
      ? ratiod_temporal::rw2_log_lik(v, sigma2, cyclic, augment)
      : ratiod_temporal::rw1_log_lik(v, sigma2, cyclic, augment);
}

// ---------------------------------------------------------------------------
// hmc_zi.h test wrappers
// ---------------------------------------------------------------------------

#include "hmc_zi.h"

// [[Rcpp::export]]
double cpp_test_log1pexp(double x) {
  return ratiod_zi::log1pexp(x);
}

// [[Rcpp::export]]
double cpp_test_zi_logistic(double x) {
  return ratiod_zi::logistic(x);
}

// [[Rcpp::export]]
double cpp_test_log_logistic(double x) {
  return ratiod_zi::log_logistic(x);
}

// [[Rcpp::export]]
double cpp_test_log1m_logistic(double x) {
  return ratiod_zi::log1m_logistic(x);
}

// [[Rcpp::export]]
double cpp_test_zi_poisson_lpmf(int y, double mu) {
  return ratiod_zi::poisson_lpmf(y, mu);
}

// [[Rcpp::export]]
double cpp_test_zi_negbin_lpmf(int y, double mu, double phi) {
  return ratiod_zi::negbin_lpmf(y, mu, phi);
}

// [[Rcpp::export]]
double cpp_test_zi_poisson_lpmf_logit(int y, double mu, double logit_zi) {
  return ratiod_zi::zi_poisson_lpmf_logit(y, mu, logit_zi);
}

// [[Rcpp::export]]
double cpp_test_zi_negbin_lpmf_logit(int y, double mu, double phi, double logit_zi) {
  return ratiod_zi::zi_negbin_lpmf_logit(y, mu, phi, logit_zi);
}

// [[Rcpp::export]]
double cpp_test_truncated_poisson_lpmf(int y, double mu) {
  return ratiod_zi::truncated_poisson_lpmf(y, mu);
}

// [[Rcpp::export]]
double cpp_test_truncated_negbin_lpmf(int y, double mu, double phi) {
  return ratiod_zi::truncated_negbin_lpmf(y, mu, phi);
}

// [[Rcpp::export]]
double cpp_test_hurdle_poisson_lpmf_logit(int y, double mu, double logit_theta) {
  return ratiod_zi::hurdle_poisson_lpmf_logit(y, mu, logit_theta);
}

// [[Rcpp::export]]
double cpp_test_hurdle_negbin_lpmf_logit(int y, double mu, double phi, double logit_theta) {
  return ratiod_zi::hurdle_negbin_lpmf_logit(y, mu, phi, logit_theta);
}

// [[Rcpp::export]]
double cpp_test_zi_log_likelihood(int y, double mu, double phi, double logit_zi, std::string zi_type_str) {
  ratiod_zi::ZIType zi_type = ratiod_zi::parse_zi_type(zi_type_str);
  return ratiod_zi::zi_log_likelihood(y, mu, phi, logit_zi, zi_type);
}

// [[Rcpp::export]]
double cpp_test_zi_poisson_grad_logit_zi(int y, double mu, double logit_zi) {
  return ratiod_zi::zi_poisson_grad_logit_zi(y, mu, logit_zi);
}

// [[Rcpp::export]]
double cpp_test_zi_negbin_grad_logit_zi(int y, double mu, double phi, double logit_zi) {
  return ratiod_zi::zi_negbin_grad_logit_zi(y, mu, phi, logit_zi);
}

// [[Rcpp::export]]
double cpp_test_hurdle_grad_logit_theta(int y, double logit_theta) {
  return ratiod_zi::hurdle_grad_logit_theta(y, logit_theta);
}

// ---------------------------------------------------------------------------
// OpenMP parallel execution tests
// ---------------------------------------------------------------------------

#ifdef _OPENMP
#include <omp.h>
#endif

// [[Rcpp::export]]
int cpp_test_get_max_threads() {
#ifdef _OPENMP
  return omp_get_max_threads();
#else
  return 1;
#endif
}

// [[Rcpp::export]]
List cpp_test_parallel_dot_products(NumericMatrix X, NumericVector y, int n_threads) {
  // Test OpenMP parallel reduction with multiple dot products
  int N = X.nrow();
  int p = X.ncol();

  std::vector<double> X_flat(N * p);
  for (int i = 0; i < N; i++) {
    for (int j = 0; j < p; j++) {
      X_flat[i * p + j] = X(i, j);
    }
  }

  NumericVector results(N);
  const double total_sum = ratiod_omp::sum_range(N, n_threads, [&](int i) {
    const double dot = ratiod_linalg::dot_product(&X_flat[i * p], y.begin(), p);
    results[i] = dot;
    return dot;
  });

  return List::create(
    Named("results") = results,
    Named("total_sum") = total_sum
  );
}

// [[Rcpp::export]]
List cpp_test_parallel_likelihood(
    IntegerVector y,
    NumericVector mu,
    int n_threads
) {
  // Test OpenMP parallel reduction for likelihood computation
  int N = y.size();
  const double log_lik = ratiod_omp::sum_range(N, n_threads, [&](int i) {
    // Poisson log-likelihood
    return mu[i] > 0 ? y[i] * std::log(mu[i]) - mu[i] - std::lgamma(y[i] + 1)
                     : 0.0;
  });

  return List::create(
    Named("log_lik") = log_lik,
    Named("n_threads_requested") = n_threads
  );
}

// Test for thread-local storage correctness
// [[Rcpp::export]]
NumericVector cpp_test_parallel_independent(int n, int n_threads) {
  // Each thread computes independent values, then we verify results
  NumericVector results(n);

#ifdef _OPENMP
  #pragma omp parallel for schedule(static) num_threads(n_threads)
#endif
  for (int i = 0; i < n; i++) {
    // Compute a deterministic function that doesn't depend on shared state
    results[i] = std::sin(i * 0.1) * std::cos(i * 0.2) + i;
  }

  return results;
}

// ---------------------------------------------------------------------------
// hmc_spatiotemporal.h: the GP interaction's field density
//
// The NNGP over a field's index set is EXACT when every location conditions on
// all of its predecessors, so at nn = n - 1 this has to reproduce the dense
// multivariate normal built from the same kernel. That identity is what pins
// the covariance assembly, the ordering and the neighbour Cholesky against the
// definition rather than against themselves; test-st-gp-density.R drives it.
// ---------------------------------------------------------------------------

#include "hmc_spatiotemporal.h"

// [[Rcpp::export]]
double cpp_test_st_gp_log_lik(
    NumericVector w,
    double sigma2,
    double phi_space,
    double phi_time,
    NumericMatrix coords,        // n x 2, by field index
    NumericVector time_values,   // n, by field index
    int nn,
    IntegerVector nn_idx,        // n x nn, row-major, 1-based within ordering
    NumericVector nn_dist_space,
    NumericVector nn_dist_time,
    IntegerVector nn_order,      // 1-based from R, stored 0-based
    std::string nonsep_type = "product",
    std::string cov_space = "exponential",
    std::string cov_time = "exponential"
) {
  ratiod_spatiotemporal::SpatiotemporalData st;
  const int n = w.size();
  st.type = ratiod_spatiotemporal::STType::NONSEP_GP;
  st.n_params = n;
  st.nn = nn;
  st.coords.resize(2 * (size_t)n);
  for (int i = 0; i < n; i++) {
    st.coords[(size_t)i * 2 + 0] = coords(i, 0);
    st.coords[(size_t)i * 2 + 1] = coords(i, 1);
  }
  st.time_values = Rcpp::as<std::vector<double>>(time_values);
  st.nn_idx = Rcpp::as<std::vector<int>>(nn_idx);
  st.nn_dist_space = Rcpp::as<std::vector<double>>(nn_dist_space);
  st.nn_dist_time = Rcpp::as<std::vector<double>>(nn_dist_time);
  std::vector<int> ord = Rcpp::as<std::vector<int>>(nn_order);
  st.nn_order.resize(ord.size());
  for (size_t i = 0; i < ord.size(); i++) st.nn_order[i] = ord[i] - 1;
  st.nn_order_inv.assign(ord.size(), 0);
  for (size_t i = 0; i < st.nn_order.size(); i++)
    st.nn_order_inv[st.nn_order[i]] = (int)i;

  if (nonsep_type == "product") {
    st.nonsep_type = ratiod_spatiotemporal::NonsepType::PRODUCT;
  } else if (nonsep_type == "gneiting") {
    st.nonsep_type = ratiod_spatiotemporal::NonsepType::GNEITING;
  } else {
    Rcpp::stop("cpp_test_st_gp_log_lik: unknown nonsep_type '%s'",
               nonsep_type.c_str());
  }
  auto parse_cov = [](const std::string& s) {
    if (s == "exponential") return ratiod_cov::CovType::EXPONENTIAL;
    if (s == "matern")      return ratiod_cov::CovType::MATERN;
    if (s == "gaussian")    return ratiod_cov::CovType::GAUSSIAN;
    if (s == "spherical")   return ratiod_cov::CovType::SPHERICAL;
    Rcpp::stop("cpp_test_st_gp_log_lik: unknown covariance '%s'", s.c_str());
    return ratiod_cov::CovType::EXPONENTIAL;
  };
  st.cov_space = parse_cov(cov_space);
  st.cov_time = parse_cov(cov_time);

  return ratiod_spatiotemporal::st_gp_nngp_log_lik(
      w.begin(), sigma2, phi_space, phi_time, st);
}

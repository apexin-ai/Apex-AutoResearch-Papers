// 4PL+γ IRT with WIDER priors (ablation for coverage diagnosis)
// P(y_ij = 1) = c_j + (d_j - c_j) * inv_logit(a_j * (theta_i - b_j) + gamma * exposure_ij)

data {
  int<lower=1> N_models;
  int<lower=1> N_items;
  array[N_models, N_items] int<lower=0, upper=1> y;
  matrix[N_models, N_items] exposure;
}

parameters {
  vector[N_models] theta;
  vector<lower=0>[N_items] a;
  vector[N_items] b;
  vector<lower=0.001, upper=0.999>[N_items] c;
  vector<lower=0.001, upper=0.999>[N_items] d;
  real gamma;
}

model {
  // Wider Priors (vs default: theta~N(0,1), a~LN(0,0.5), b~N(0,1), c~B(5,20), d~B(20,5), gamma~N(0,1))
  theta ~ normal(0, 3);
  a ~ lognormal(0, 1);
  b ~ normal(0, 3);
  c ~ beta(2, 8);
  d ~ beta(8, 2);
  gamma ~ normal(0, 5);

  // Likelihood
  for (i in 1:N_models) {
    for (j in 1:N_items) {
      real eta = a[j] * (theta[i] - b[j]) + gamma * exposure[i, j];
      real p = c[j] + (d[j] - c[j]) * inv_logit(eta);
      y[i, j] ~ bernoulli(p);
    }
  }
}

generated quantities {
  // Calibrated scores: P(y=1 | exposure=0)
  array[N_models] real calibrated_score;
  for (i in 1:N_models) {
    real total = 0.0;
    for (j in 1:N_items) {
      real eta_clean = a[j] * (theta[i] - b[j]);
      real p_clean = c[j] + (d[j] - c[j]) * inv_logit(eta_clean);
      total += p_clean;
    }
    calibrated_score[i] = total / N_items;
  }

  // Log-likelihood for LOO-CV
  vector[N_models * N_items] log_lik;
  {
    int idx = 0;
    for (i in 1:N_models) {
      for (j in 1:N_items) {
        idx += 1;
        real eta = a[j] * (theta[i] - b[j]) + gamma * exposure[i, j];
        real p = c[j] + (d[j] - c[j]) * inv_logit(eta);
        log_lik[idx] = bernoulli_lpmf(y[i, j] | p);
      }
    }
  }
}

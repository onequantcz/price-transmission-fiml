#==========================================================================================================================================
# Custom implementation of Full Information Maximum Likelihood and extensions
#
# Features:
# - arbitrary structural restrictions through masks
# - numerical likelihood maximization
# - momentum-based gradient descent
# - numerical Hessian estimation
# - Fisher information matrix
# - p-values and standard errors
# - AIC and BIC
#
#Optimizer works with masks, so constraints should be written in matrix form, where 1 is parameter for optimization, and 0 is a constraint.
# =========================================================================================================================================


FIML <- function(mask_B, mask_G, X, Y, learning_rate = 1e-3, iterations = 1e3, param_convergence = 1e-4, likelihood_convergence = 1e-5, inert = 0.9) {
  
  t <- nrow(Y)
  n <- ncol(Y)
  k <- ncol(X)
  
# =============================================================================
# Index builder. Decomposes masks to parameters vector for further optimization
# =============================================================================
  build_index <- function(mask_B, mask_G) {
    
    idx <- list()
    counter <- 1
    
    idx$B <- matrix(NA, nrow(mask_B), ncol(mask_B))
    
    for (i in 1:nrow(mask_B)) {
      for (j in 1:ncol(mask_B)) {
        if (mask_B[i,j] == 1) {
          idx$B[i,j] <- counter
          counter <- counter + 1
        }
      }
    }
    
    idx$G <- matrix(NA, nrow(mask_G), ncol(mask_G))
    
    for (i in 1:nrow(mask_G)) {
      for (j in 1:ncol(mask_G)) {
        if (mask_G[i,j] == 1) {
          idx$G[i,j] <- counter
          counter <- counter + 1
        }
      }
    }
    
    idx$n_params <- counter - 1
    
    return(idx)
  }
  
# ========================================== 
# Unpacks vector of parameters back to masks
# ==========================================
  unpack_params <- function(theta, idx, mask_B, mask_G) {
    
    B <- matrix(0, nrow(mask_B), ncol(mask_B))
    
    for (i in 1:nrow(mask_B)) {
      for (j in 1:ncol(mask_B)) {
        if (mask_B[i,j] == 1) {
          B[i,j] <- theta[idx$B[i,j]]
        }
      }
    }
    
    diag(B) <- 1
    
    G <- matrix(0, nrow(mask_G), ncol(mask_G))
    
    for (i in 1:nrow(mask_G)) {
      for (j in 1:ncol(mask_G)) {
        if (mask_G[i,j] == 1) {
          G[i,j] <- theta[idx$G[i,j]]
        }
      }
    }
    
    return(list(B = B, G = G))
  }
  
  params <- rep(1.5, build_index(mask_B, mask_G)$n_params)
  
# ================================================================
# Logarithmic likelihood function, which will be further optimized 
# ================================================================
  log_likelihood <- function(mask_B, mask_G, X, Y, params) {
    
    t <- nrow(Y)
    n <- ncol(Y)
    k <- ncol(X)
    
    idx <- build_index(mask_B, mask_G)
    unpack <- unpack_params(params, idx, mask_B, mask_G)
    B <- unpack$B
    G <- unpack$G
    
    u <- Y %*% t(B) + X %*% t(G)
    P <- -solve(B) %*% G
    C <- (1 / t) * (t(u) %*% u)
    v <- u %*% t(solve(B))
    S <- (1 / t) * (t(v) %*% v)
    
    #L <- -(t/2) * log(det(S)) - 1/2 * sum(diag(solve(S) %*% t(v) %*% v)) - (t * n / 2) * log(2 * pi)
    L <- t * log(det(B)) - t/2 * log(det(C)) - 1/2 * sum(diag(solve(C) %*% t(u) %*% u))  - (t*n/2) * log(2 * pi) #equivalent, just more handy form
    return(L)
  }
  
# =========================================
# Numeric gradient using finite differences
# =========================================
  gradient <- function(params) {
    
    gradient <- params
    
    for (i in seq_along(gradient)) {
      
      tmp_plus <- params
      tmp_plus[i] <- params[i] + 1e-5
      tmp_plus <- tmp_plus
      tmp_minus <- params
      tmp_minus[i] <- params[i] - 1e-5
      tmp_minus <- tmp_minus
      gradient[i] <- (log_likelihood(mask_B, mask_G, X, Y, tmp_plus) - log_likelihood(mask_B, mask_G, X, Y, tmp_minus)) / (2 * 1e-5)
    }
    
    return(gradient)
  }
  
# ============
# Start of GD
# ============
  likelihood_history <- numeric(iterations)
  params_old <- params
  params_new <- params
  params_lookahead <- params
  v <- numeric(length(params))
  v_new <- v
  
  for (iter in 1:iterations) {
    
    params_lookahead <- params_old + inert * v
    grad <- gradient(params_lookahead)
    v_new <- inert * v + learning_rate * grad
    
    step <- 1
    L_old <- log_likelihood(mask_B, mask_G, X, Y, params_old)

# =============================
# Line search for learning rate 
# =============================
    repeat {
      params_candidate <- params_old + step * v_new
      L_new <- log_likelihood(mask_B, mask_G, X, Y, params_candidate)
      
      if (is.finite(L_new) && L_new >= L_old) break
      
      step <- step * 0.5
      if (step < 1e-8) break
    }
    
    params_new <- params_old + step * v_new
    
    #cat(params_new, "\n") 

# ================================== 
# Convergence criteria or bug report
# ==================================
    if(any(!is.finite(params_new))) {
      cat("параметры улетели\n")
      break
    }
    
    if (abs(L_new - L_old) < likelihood_convergence) {
      cat("сходимость по likelihood на итерации ", iter, "\n")
      params_old <- params_new
      break
    }
    
    if(all(abs(params_old - params_new) < param_convergence, na.rm = TRUE)) { 
      cat("сходимость по параметрам достигнута на итерации ", iter, "\n") 
      params_old <- params_new 
      break 
    }
    
    likelihood_history[iter] <- L_new
    
    params_old <- params_new
    v <- step * v_new
  }
  
  estimated_params <- params_old
  idx <- build_index(mask_B, mask_G)
  
  param_names <- character(idx$n_params)
  for (i in 1:nrow(mask_B)) {
    for (j in 1:ncol(mask_B)) {
      if (!is.na(idx$B[i,j])) {
        param_names[idx$B[i,j]] <- paste0("B[", i, ",", j, "]")
      }
    }
  }
  for (i in 1:nrow(mask_G)) {
    for (j in 1:ncol(mask_G)) {
      if (!is.na(idx$G[i,j])) {
        param_names[idx$G[i,j]] <- paste0("G[", i, ",", j, "]")
      }
    }
  }
  
  B <- unpack_params(estimated_params, idx, mask_B, mask_G)$B
  G <- unpack_params(estimated_params, idx, mask_B, mask_G)$G
  P <- -solve(B) %*% G
  
# =============================================== 
# Numeric hessian for parameter significance test
# =============================================== 
  hessian <- function(estimated_params) {
    
    H <- matrix(nrow = length(estimated_params), ncol = length(estimated_params))
    
    eps <- 1e-4
    for (i in seq_along(estimated_params)) {
      
      for (j in seq_along(estimated_params)) {
        
        if (i == j) {
          tmp <- estimated_params
          tmp_plus <- estimated_params
          tmp_minus <- estimated_params
          tmp_plus[i] <- tmp_plus[i] + eps
          tmp_minus[i] <- tmp_minus[i] - eps
          H[i, j] <- (log_likelihood(mask_B, mask_G, X, Y, tmp_plus)  - 2 * log_likelihood(mask_B, mask_G, X, Y, tmp)  + log_likelihood(mask_B, mask_G, X, Y, tmp_minus)) / ((eps)^2)
        }
        
        if (i != j) {
          tmp_plus_plus <- estimated_params
          tmp_plus_plus[i] <- tmp_plus_plus[i] + eps
          tmp_plus_plus[j] <- tmp_plus_plus[j] + eps
          tmp_plus_minus <- estimated_params
          tmp_plus_minus[i] <- tmp_plus_minus[i] + eps
          tmp_plus_minus[j] <- tmp_plus_minus[j] - eps
          tmp_minus_plus <- estimated_params
          tmp_minus_plus[i] <- tmp_minus_plus[i] - eps
          tmp_minus_plus[j] <- tmp_minus_plus[j] + eps
          tmp_minus_minus <- estimated_params
          tmp_minus_minus[i] <- tmp_minus_minus[i] - eps
          tmp_minus_minus[j] <- tmp_minus_minus[j] - eps
          H[i, j] <- (log_likelihood(mask_B, mask_G, X, Y, tmp_plus_plus) - log_likelihood(mask_B, mask_G, X, Y, tmp_plus_minus) - log_likelihood(mask_B, mask_G, X, Y, tmp_minus_plus) 
                      + log_likelihood(mask_B, mask_G, X, Y, tmp_minus_minus)) / (4 * (eps)^2)
        }
      }
    }
    
    return(H)
  }
  H <- hessian(estimated_params)
  active <- apply(abs(H), 1, function(x) any(x > 1e-8))
  H_reduced <- H[active, active]
  params_reduced <- estimated_params[active]
  names_reduced <- param_names[active]
  
  I_inv <- solve(-H_reduced)
  se_reduced <- sqrt(abs(diag(I_inv)))
  p_values_reduced <- 2 * (1 - pnorm(abs(params_reduced / se_reduced)))
  p_values <- data.frame(p_values_reduced, names_reduced)
  
  lh <- log_likelihood(mask_B, mask_G, X, Y, estimated_params)
  AIC <- -2 * lh + 2 * k
  BIC <- -2 * lh + k * log(n)
  
  return(return(list(likelihood_history = likelihood_history, B = B, G = G, P = P, p_values = p_values, lh = lh, AIC = AIC, BIC = BIC, I_inv = I_inv)))
}


# ==========================================
# Likelihood ratio test for model comparsion
# ==========================================
LRtest <- function(model_full, model_restricted) {
  
  k_full <- sum(model_full$B != 0) - ncol(model_full$B) + sum(model_full$G != 0) + (ncol(model_full$B)*(ncol(model_full$B)+1))/2
  k_restricted <- sum(model_restricted$B != 0) - ncol(model_restricted$B) + sum(model_restricted$G != 0) + (ncol(model_restricted$B)*(ncol(model_restricted$B)+1))/2
  df <- k_full - k_restricted
  LR <- 2 * (model_full$lh - model_restricted$lh)
  p_value <- 1 - pchisq(LR, df)
  
  return(list(LR = LR, df = df, p_value = p_value))
} 
                       
# ===================
# Farrar-Glauber test 
# ===================                
FGtest <- function(X) { 
  
  p = ncol(X)
  df <- ((p * (p - 1)) / 2)
  B <- -(nrow(X) - 1 - (1/6 * (2 * p + 5))) * log(det(corm(X)))
  p_value <- 1 - pchisq(B, df = df)
  return(list(p_value = p_value, B = B, df = df))
}


# ==================
# Breusch-Pagan test
# ==================
BPtest <- function(errors, X, intercept = TRUE) {
  
  tmp <- OLS(X, (errors^2), lambda = 0, intercept = intercept)
  LM <- nrow(X) * tmp$R2
  df <- ncol(X)
  p_value <- 1 - pchisq(LM, df)
  return(list(LM = LM, p_value = p_value))
}


# =================
# Ramsey RESET test
# =================
RESETtest <- function(X, Y, h = 3, intercept = TRUE) {
  
  model0 <- OLS(X, Y, lambda = 0, intercept = intercept)
  RSS0 <- sum((Y - model0$estimate)^2)
  
  tmp <- matrix(nrow = nrow(Y), ncol = (h-1))
  for (i in 2:h) {
    tmp[, i-1] <- (model0$estimate)^i
  }
  tmp <- cbind(X, tmp)
  
  model1 <- OLS(tmp, Y, lambda = 0, intercept = intercept)
  RSS1 <- sum((Y - model1$estimate)^2)
  
  q <- h - 1
  k1 <- ncol(tmp)
  if (intercept) k1 <- k1 + 1
  F_stat <- ((RSS0 - RSS1) / q) / (RSS1 / (nrow(X) - k1))
  p_value <- 1 - pf(F_stat, q, (nrow(X) - k1))
  return(list(F_stat = F_stat, p_value = p_value))
}


                  

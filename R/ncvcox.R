#' Non-convex penalized Cox proportional hazards model
#'
#' @param formula A formula object, with the response on the left of a \code{~}
#' operator, and the terms on the right. The response must be a survival object
#' as returned by the Surv function.
#' @param data A data frame containing the variables in the model.
#' @param group A factor variable indicating the group of each observation.
#' @param lambda A non-negative value specifying the penalty parameter. The
#' default is 0.
#' @param penalty A character string specifying the penalty function. The
#' default is "lasso". Other options are "MCP" and "SCAD".
#' @param gamma A non-negative value specifying the penalty parameter. The
#' default is 3.7 for SCAD and 3.0 for MCP.
#' @param init A numeric vector of initial values for the coefficients. The
#' default is a zero vector.
#' @param control An object of class \link{survtrans_control} containing control
#' parameters for the fitting algorithm. Default is
#' \code{survtrans_control(...)}.
#' @param ... Additional arguments to be passed to the fitting algorithm.
#' @return An object of class \code{ncvcox}.
#' @export
#' @examples
#' formula <- Surv(time, status) ~ . - group - id
#' df <- sim2[sim2$group == 2 | sim2$group == 4, ]
#' fit <- ncvcox(formula, df, df$group, lambda = 0.1, penalty = "SCAD")
#' summary(fit)
ncvcox <- function(
  formula, data, group, lambda = 0,
  penalty = c("lasso", "MCP", "SCAD"),
  gamma = switch(penalty,
    SCAD = 3.7,
    MCP = 3,
    1
  ), init, control, ...
) {
  # Load the data
  data <- preprocess(formula, data, group = group)
  x <- data$x
  x_scale <- attr(x, "scaled:scale")
  time <- data$time
  status <- data$status
  group <- data$group

  # Properties of the data
  n_samples <- nrow(x)
  n_features <- ncol(x)
  n_groups <- length(unique(group))
  group_levels <- levels(group)
  group_idxs <- lapply(group_levels, function(g) which(group == g))

  # Check the penalty argument
  penalty <- match.arg(penalty, choices = c("lasso", "MCP", "SCAD"))

  # Check the init argument
  if (!missing(init) && length(init) > 0) {
    if (length(init) != n_features) {
      stop("Wrong length for initial values")
    }
  } else {
    init <- numeric(n_features)
  }

  # Check the control argument
  if (missing(control)) control <- survtrans_control(...)

  # Initialize the training process
  n_iterations <- 0
  msg <- ""
  converged <- FALSE
  beta <- init

  offset <- x %*% beta
  w <- numeric(n_samples)
  r <- numeric(n_samples)

  x2 <- x^2

  repeat {
    n_iterations <- n_iterations + 1
    beta_prev <- beta

    # Calculate the weights and residuals
    for (k in seq_len(n_groups)) {
      idx <- group_idxs[[k]]
      wls <- approx_likelihood(
        offset = offset[idx], time = time[idx], status = status[idx]
      )
      w[idx] <- wls$weights
      r[idx] <- wls$residuals
    }
    xw <- x * w
    xwx <- colMeans(x2 * w)

    # Update beta by cyclic coordinate descent
    repeat {
      max_diff <- 0
      for (j in seq_len(n_features)) {
        beta_j <- beta[j]
        u <- mean(xw[, j] * r) + xwx[j] * beta_j
        v <- xwx[j]
        beta[j] <- close_update(u, v, penalty, lambda, gamma)
        shift <- beta[j] - beta_j
        if (shift != 0) {
          r <- r - x[, j] * shift
          max_diff <- max(max_diff, abs(shift) * sqrt(v))
        }
      }
      if (max_diff <= control$abstol) break
    }

    # Calculate the log-likelihood
    offset <- x %*% beta
    hazard <- exp(offset)
    risk_set <- calc_risk_set(hazard, time, group_idxs)
    loss <- sum(status * (offset - log(risk_set)))
    loss_penalty <- penalty_value(beta, penalty, lambda, gamma) * n_samples
    loss_total <- loss - loss_penalty
    if (control$verbose) {
      cat(
        "========================================\n",
        sprintf("Iteration Number       : %d", n_iterations), "\n",
        sprintf("Total Loss             : %.4f", loss_total), "\n",
        sprintf(" - Log Likelihood      : %.4f", loss), "\n",
        sprintf(" - Penalty             : %.4f", loss_penalty), "\n",
        "========================================\n"
      )
    }

    # Check convergence (order: convergence > early stop > maxit)
    if (max(abs(beta - beta_prev)) <= control$abstol) {
      converged <- TRUE
      msg <- sprintf("Convergence reached at iteration %d.", n_iterations)
    } else if (is.infinite(loss) || is.nan(loss)) {
      converged <- TRUE
      msg <- "Log-likelihood is not finite. Stopping."
    } else if (n_iterations >= control$maxit) {
      converged <- TRUE
      msg <- sprintf("Maximum number of iterations reached (%d).", control$maxit)
    }
    if (converged) break
  }

  # Unstandardize coefficients and design matrix (match coxtrans convention)
  coefficients <- beta / x_scale
  names(coefficients) <- colnames(x)
  x <- sweep(x, 2, x_scale, "*")

  # Return the fit
  fit <- list(
    coefficients = coefficients,
    logLik = loss,
    iter = n_iterations,
    message = msg,
    penalty = penalty,
    lambda = lambda,
    gamma = gamma,
    formula = formula,
    call = match.call(),
    time = time,
    status = status,
    group = group,
    x = x
  )
  class(fit) <- "ncvcox"
  return(fit)
}

#' Extract the coefficients from a \code{ncvcox} object
#' @param object An object of class \code{ncvcox}.
#' @param ... Additional arguments (unused).
#' @return A named numeric vector containing the coefficients of the fitted
#' \code{ncvcox} object. Zero coefficients are removed.
#' @export
coef.ncvcox <- function(object, ...) {
  coefficients <- object$coefficients
  names(coefficients) <- colnames(object$x)
  coefficients[coefficients != 0]
}

#' Variance-covariance matrix for a \code{ncvcox} object.
#' @param object An object of class \code{ncvcox}.
#' @param ... Additional arguments (unused).
#' @return A matrix representing the variance-covariance matrix of the
#' coefficients.
#' @export
vcov.ncvcox <- function(object, ...) {
  # Properties of the ncvcox object
  time <- object$time
  status <- object$status
  group <- object$group
  x <- object$x
  n_samples <- nrow(x)
  group_levels <- levels(group)
  n_groups <- length(group_levels)
  group_idxs <- lapply(group_levels, function(g) which(group == g))
  coefficients <- object$coefficients

  # Select the non-zero coefficients and corresponding variables
  coefs <- coefficients[coefficients != 0]
  x <- as.matrix(x[, coefficients != 0, drop = FALSE])
  n_nonzero <- length(coefs)

  # Calculate the gradient and Hessian for the non-zero coefficients
  lp <- x %*% coefs
  gradients <- matrix(0, nrow = n_samples, ncol = n_nonzero)
  hessians <- matrix(0, nrow = n_samples, ncol = n_nonzero^2)
  for (k in seq_len(n_groups)) {
    idx <- group_idxs[[k]]
    ghs <- calc_grad_hess(
      lp[idx], x[idx, , drop = FALSE], time[idx], status[idx]
    )
    gradients[idx, ] <- ghs$grad
    hessians[idx, ] <- ghs$hess
  }
  hess <- matrix(colSums(hessians), n_nonzero, n_nonzero)
  hess_inv <- solve(hess)
  grad_cov <- crossprod(gradients)
  vcov <- hess_inv %*% grad_cov %*% hess_inv
  dimnames(vcov) <- list(names(coefs), names(coefs))
  vcov
}

#' @title Log-likelihood for a \code{ncvcox} object
#'
#' @param object An object of class \code{ncvcox}.
#' @param ... Additional arguments (unused).
#' @return A numeric value representing the log-likelihood of the fitted
#' \code{ncvcox} object.
#' @export
logLik.ncvcox <- function(object, ...) {
  # Properties of the ncvcox object
  time <- object$time
  status <- object$status
  group <- object$group
  x <- object$x
  n_groups <- length(unique(group))
  group_levels <- levels(group)
  group_idxs <- lapply(group_levels, function(g) which(group == g))
  coefficients <- object$coefficients

  offset <- x %*% coefficients
  hazard <- exp(offset)
  risk_set <- calc_risk_set(hazard, time, group_idxs)
  sum(status * (offset - log(risk_set)))
}

#' Summary method for a \code{ncvcox} object
#'
#' @param object An object of class \code{ncvcox}.
#' @param conf.int A numeric value between 0 and 1 indicating the confidence
#' level of the confidence interval. Default is 0.95.
#' @param compressed Logical; if \code{TRUE}, the summary is compressed and
#' only includes the group-level coefficients. Default is \code{TRUE}.
#' @param ... Additional arguments (not used).
#'
#' @return An object of class \code{summary.ncvcox}, with the following
#' components:
#' \item{\code{n}, \code{nevent}}{Number of observations and number of events,
#' respectively, in the fit.}
#' \item{\code{logLik}}{The log partial likelihood at the final value.}
#' \item{\code{coefficients}}{A matrix with one row for each coefficient, and
#' columns containing the coefficient, the hazard ratio exp(coef), standard
#' error, Wald statistic, and P value.}
#' \item{\code{conf.int}}{A matrix with one row for each coefficient, containing
#' the confidence limits for exp(coef).}
#'
#' @export
summary.ncvcox <- function(object, conf.int = 0.95, compressed = TRUE, ...) {
  # Extract necessary components from the object
  n_samples <- nrow(object$x)
  n_events <- sum(object$status)
  loglik <- logLik(object)

  # Standard errors
  vcov_matrix <- vcov(object)
  if (is.null(vcov_matrix)) {
    stop("Variance-covariance matrix is not available.")
  }
  se <- sqrt(diag(vcov_matrix))

  coefficients <- coef(object)
  z_scores <- coefficients / se
  p_values <- stats::pchisq(z_scores^2, 1, lower.tail = FALSE)
  coef_matrix <- cbind(
    coefficients, exp(coefficients), se, z_scores, p_values
  )
  dimnames(coef_matrix) <- list(
    names(coefficients), c("coef", "exp(coef)", "se(coef)", "z", "Pr(>|z|)")
  )

  z <- stats::qnorm((1 + conf.int) / 2)
  conf_int_matrix <- cbind(
    exp(coefficients), exp(-coefficients),
    exp(coefficients - z * se), exp(coefficients + z * se)
  )
  dimnames(conf_int_matrix) <- list(
    names(coefficients), c(
      "exp(coef)", "exp(-coef)",
      stringr::str_c("lower .", round(100 * conf.int, 2), sep = ""),
      stringr::str_c("upper .", round(100 * conf.int, 2), sep = "")
    )
  )

  if (!compressed) {
    coef_matrix_extract <- coef_matrix
    conf_int_matrix_extract <- conf_int_matrix

    coef_names <- names(coefficients)
    variable_names <- colnames(object$x)
    missing_names <- setdiff(variable_names, coef_names)

    if (length(missing_names) > 0) {
      for (name in missing_names) {
        coef_matrix_extract <- rbind(coef_matrix_extract, c(NA, NA, NA, NA, NA))
        conf_int_matrix_extract <- rbind(
          conf_int_matrix_extract, c(NA, NA, NA, NA)
        )
        coef_names <- c(coef_names, name)
      }
    }
    coef_order <- match(variable_names, coef_names)
    coef_matrix <- coef_matrix_extract[coef_order, ]
    conf_int_matrix <- conf_int_matrix_extract[coef_order, ]
    rownames(coef_matrix) <- variable_names
    rownames(conf_int_matrix) <- variable_names
  }

  # Create a summary list
  summary_list <- list(
    n = n_samples,
    nevent = n_events,
    logLik = loglik,
    call = object$call,
    coefficients = coef_matrix,
    conf.int = conf_int_matrix
  )

  class(summary_list) <- "summary.ncvcox"
  summary_list
}

#' Print method for a \code{summary.ncvcox} object
#' @description This function prints a summary of the results of a
#' \code{ncvcox} model in a formatted and user-friendly manner, including the
#' model call, number of samples, number of events, coefficients, and confidence
#' intervals. It also includes
#' significance stars for p-values.
#' @param x A summary object produced from a fitted \code{ncvcox} model. This
#' object contains information such as model coefficients and confidence
#' intervals.
#' @param digits An integer controlling the number of significant digits to
#' print for numeric values.
#' @param signif.stars Logical; if \code{TRUE}, significance stars are printed
#' along with the p-values.
#' @param ... Additional arguments (unused).
#' @return The function prints the summary of the \code{ncvcox} model and
#' returns the object \code{x} invisibly.
#' @details The function provides a formatted output that includes:
#' \itemize{
#'   \item \strong{Call:} The original function call that produced the model.
#'   \item \strong{n and events:} The total number of samples and the number of
#'         events (e.g., deaths).
#'   \item \strong{Coefficients:} The regression coefficients, their standard
#'         errors, z-values, and p-values, formatted in a table. Significance
#'         stars are shown next to p-values if \code{signif.stars} is
#'         \code{TRUE}.
#'   \item \strong{Confidence intervals:} The exponentiated coefficients along
#'         with their confidence intervals.
#' }
#' @export
print.summary.ncvcox <- function(
  x, digits = max(getOption("digits") - 3, 3),
  signif.stars = getOption("show.signif.stars"), ...
) {
  # Print call
  cat("Call:\n")
  print(x$call)
  cat("\n")

  # Print number of samples and events
  cat("  n=", x$n, ", number of events=", x$nevent, "\n\n", sep = "")

  # Print coefficients with formatted output
  stats::printCoefmat(x$coefficients,
    digits = digits, signif.stars = signif.stars,
    cs.ind = 1:3, tst.ind = 4, P.values = TRUE, has.Pvalue = TRUE
  )

  # Print confidence intervals
  print(format(x$conf.int, digits = digits), quote = FALSE)

  invisible(x)
}

#' Prediction method for \code{ncvcox} objects.
#' @param object An object of class \code{ncvcox}.
#' @param newdata Optional new data for making predictions. If omitted,
#'   predictions are made using the data used for fitting the model.
#' @param newgroup Optional new group for making predictions. If omitted,
#'   predictions are made using the groups from the original data.
#' @param type The type of prediction to perform. Options include:
#'   \describe{
#'     \item{\code{"lp"}}{The linear predictor.}
#'     \item{\code{"risk"}}{The risk score \eqn{\exp(\text{lp})}.}
#'   }
#' @param ... Additional arguments (unused).
#' @return A numeric vector of predictions.
#' @export
predict.ncvcox <- function(
  object, newdata = NULL, newgroup = NULL,
  type = c("lp", "risk"), ...
) {
  type <- match.arg(type)
  x <- stats::model.matrix(object$formula, newdata)[, -1]
  lp <- as.numeric(x %*% object$coefficients)
  if (type == "risk") lp <- exp(lp)
  lp
}
#' Predict the cumulative baseline hazard function for \code{ncvcox} objects
#'
#' @param object An object of class \code{ncvcox}.
#' @param ... Additional arguments (unused).
#'
#' @return A \code{data.frame} with one row for each time point, and columns
#' containing the event time, the cumulative baseline hazard function, and the
#' strata.
#' @export
basehaz.ncvcox <- function(object, ...) {
  # Properties of the ncvcox object
  time <- object$time
  status <- object$status
  group <- object$group
  x <- object$x
  n_groups <- length(unique(group))
  group_levels <- levels(group)
  group_idxs <- lapply(group_levels, function(g) which(group == g))
  offset <- x %*% object$coefficients
  hazard <- exp(offset)
  risk_set <- calc_risk_set(hazard, time, group_idxs)

  basehaz_list <- vector("list", n_groups)
  for (k in seq_len(n_groups)) {
    idx <- group_idxs[[k]]
    time_rev <- rev(time[idx])
    status_rev <- rev(status[idx])
    risk_set_rev <- rev(risk_set[idx])
    basehaz <- cumsum(status_rev / risk_set_rev)
    basehaz_list[[k]] <- data.frame(
      time = time_rev[status_rev == 1],
      basehaz = basehaz[status_rev == 1],
      strata = group_levels[k]
    )
  }
  basehaz_df <- do.call(rbind, basehaz_list)
  if (n_groups == 1) {
    basehaz_df$strata <- NULL
  }
  basehaz_df
}

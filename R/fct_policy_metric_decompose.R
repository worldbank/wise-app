# Row-aligned central policy channels shared by production and attribution.
# Unit-exposure evaluations use the existing kernels, not a second formula map.

.policy_explicit_channels <- function(context, hazards, weather_vars = context$weather_vars) {
  if (identical(context$engine, "rif")) {
    .compute_rif_channels(
      context$svy_baseline, context$deltas, context$sp_transfer,
      hazards, weather_vars, context$rif_grid, context$taus,
      context$train_data, context$outcome, context$is_log,
      skip_coef = TRUE, central_only = TRUE, context = context, so = context$so
    )
  } else {
    suppressWarnings(.decompose_ols(
      context$svy_baseline, context$model_fit, context$so,
      context$deltas, context$sp_transfer, hazards, weather_vars,
      context$n, skip_coef = TRUE, central_only = TRUE, context = context
    ))
  }
}

.policy_annual_channel_status <- function(context) {
  endpoint <- .policy_endpoint_status(context$so, context)
  if (!identical(endpoint$status, "ok")) return(endpoint)
  if (is.null(context$engine) || !context$engine %in% c("rif", "fixest")) {
    return(list(status = "unsupported", reason = "Annual channels require RIF or linear fixest."))
  }
  transform <- context$so$transform
  if (!is.null(transform) && !is.na(transform) &&
    !transform %in% c("log", "none", "identity")) {
    return(list(status = "unsupported", reason = "Annual channels require identity or log outcomes."))
  }
  list(status = "ok", reason = NULL)
}

.prepare_policy_annual_channels <- function(context, run_identity, shock = NULL) {
  .validate_run_decomposition_context(context, run_identity)
  endpoint <- .policy_annual_channel_status(context)
  if (!identical(endpoint$status, "ok")) return(endpoint)
  if (!is.null(shock) && length(shock$per_household) != context$n) {
    stop("Shock plan does not match the run's survey rows.", call. = FALSE)
  }
  vars <- context$weather_vars
  n <- context$n
  zero <- setNames(lapply(vars, function(v) {
    x <- context$svy_baseline[[v]]
    if (is.factor(x)) factor(rep(levels(x)[1L], n), levels = levels(x)) else rep(0, n)
  }), vars)
  # Main/ranks are invariant to weather. The full call also records whether
  # fitted interactions are present, including categories absent in this run.
  base <- .policy_explicit_channels(context, zero)
  if (is.null(base) || any(!is.finite(base$delta_main))) {
    return(list(status = "unavailable", reason = "Canonical main channel is unavailable or nonfinite."))
  }
  # DOC-10: the main effect is the effect of the policy at the weather the
  # household experienced at its interview, so the weather channels evaluated
  # at that weather (the interaction gamma * dD * W0; for the quantile model
  # also the repositioning) belong to it. It is a household constant, so the
  # main effect still does not vary with the simulated weather. The weather
  # channels of a prediction row act on the change from this weather only, and
  # main + repositioning + interaction is the full effect at the row's weather.
  at_interview <- .policy_explicit_channels(context, setNames(
    lapply(vars, function(v) context$svy_baseline[[v]]), vars))
  at_interview_w0 <- at_interview$delta_res1 + at_interview$delta_res2
  if (any(!is.finite(at_interview_w0))) {
    return(list(status = "unavailable", reason = "Main effect at the interview weather is nonfinite."))
  }
  base$delta_main_covar <- base$delta_main_covar + at_interview_w0
  base$delta_main <- base$delta_main + at_interview_w0
  products <- setNames(lapply(vars, function(v) {
    x <- context$svy_baseline[[v]]
    categories <- if (is.factor(x)) levels(x) else NULL
    values <- if (is.null(categories)) 1 else categories
    r1 <- r2 <- matrix(0, nrow = n, ncol = length(values))
    for (j in seq_along(values)) {
      hazards <- zero
      hazards[[v]] <- if (is.null(categories)) rep(1, n) else {
        factor(rep(values[j], n), levels = categories)
      }
      ch <- .policy_explicit_channels(context, hazards, weather_vars = v)
      r1[, j] <- ch$delta_res1
      r2[, j] <- ch$delta_res2
    }
    list(categories = categories, repositioning = r1, interaction = r2)
  }), vars)
  # Each category stores its own fitted-reference contrast. No assumption about
  # the first factor level or division by observed hazards is needed.
  if (any(!is.finite(c(base$delta_res1, base$delta_res2,
    unlist(lapply(products, function(p) c(p$repositioning, p$interaction))))))) {
    return(list(status = "unavailable", reason = "Canonical sensitivity channels are nonfinite."))
  }
  prepared <- list2env(list(
    status = "ok", context = context, run_identity = run_identity,
    delta_sp = base$delta_sp, delta_main_covar = base$delta_main_covar,
    delta_main = base$delta_main, products = products,
    repositioning_modeled = identical(context$engine, "rif"),
    interaction_included = base$has_interactions,
    tau_i_pre = context$tau_i_pre, tau_i_post = context$tau_i_post,
    shock = shock,
    loading_terms = if (identical(context$engine, "fixest") && !is.null(context$coef_L)) {
      .policy_loading_terms(context)
    } else if (identical(context$engine, "rif") && !is.null(context$coef_chol_list)) {
      .policy_loading_terms_rif(context)
    },
    correction_version = "row_aligned_annual_v1"
  ), parent = emptyenv())
  lockEnvironment(prepared, bindings = TRUE)
  prepared
}

.validate_policy_annual_exposure <- function(pipeline, context, owner = NULL,
                                              cache = NULL) {
  # Schema-2 pipelines store a compact recipe; rebuild the exact mapping from
  # the pipeline's weather, resolved against its owning scenario.
  exposure <- step2_exposure_resolve(pipeline, owner, cache)
  if (is.null(exposure) || !identical(exposure$status, "ok")) {
    stop("Exact prediction-row weather exposure mapping unavailable.", call. = FALSE)
  }
  n <- length(pipeline$y_point)
  if (!n) stop("Empty baseline prediction pipeline.", call. = FALSE)
  fields <- c("svy_row_id", "sim_year", "weight", "id_vec")
  for (field in fields) {
    if (!identical(pipeline[[field]], exposure[[field]])) {
      stop("Prediction/exposure ordering mismatch: ", field, call. = FALSE)
    }
  }
  ids <- pipeline$svy_row_id
  idx <- exposure$row_index
  ordinal <- exposure$prediction_row_id
  key_cols <- c("code", "year", "survname", "loc_id", "int_month", "timestamp")
  # Everything below except the weather values depends only on the row
  # structure (ids, years, weights, anchor index and the anchor key columns).
  # Members of one scenario share it, so a member whose structure is identical
  # to one that already passed skips the per-row scans (identical() on the same
  # vectors is a memory compare). The weather values are checked per member.
  structure <- if (all(key_cols %in% names(exposure$table))) {
    list(context = context, n = n, ids = ids, sim_year = pipeline$sim_year,
      weight = pipeline$weight, idx = idx, ordinal = ordinal,
      keys = exposure$table[key_cols])
  }
  validated <- is.environment(cache) && !is.null(structure) &&
    identical(cache$validated_structure, structure)
  if (validated) {
    absent <- setdiff(context$weather_vars, names(exposure$table))
    missing <- if (length(absent)) absent else context$weather_vars[vapply(
      context$weather_vars, function(key) anyNA(exposure$table[[key]][idx]),
      logical(1))]
    if (length(missing)) {
      stop("Missing exact weather exposure or anchor identity: ",
        paste(missing, collapse = ", "), call. = FALSE)
    }
  } else {
    valid_index <- function(x, upper) is.numeric(x) && length(x) == n &&
      !anyNA(x) && all(x == as.integer(x) & x >= 1 & x <= upper)
    if (!valid_index(ids, context$n) || length(pipeline$sim_year) != n ||
      anyNA(pipeline$sim_year) || !is.data.frame(exposure$table) ||
      !valid_index(idx, nrow(exposure$table)) || !valid_index(ordinal, Inf) ||
      anyDuplicated(ordinal)) {
      stop("Invalid prediction-row exposure identifiers.", call. = FALSE)
    }
    required <- c(key_cols, context$weather_vars)
    absent <- setdiff(required, names(exposure$table))
    missing <- if (!length(absent)) required[vapply(required,
      function(key) anyNA(exposure$table[[key]][idx]), logical(1))] else absent
    if (length(missing)) {
      stop("Missing exact weather exposure or anchor identity: ",
        paste(missing, collapse = ", "), call. = FALSE)
    }
    join_keys <- c("code", "year", "survname", "loc_id", "int_month")
    if (!all(join_keys %in% names(context$svy_baseline))) {
      stop("Survey join identity unavailable in run context.", call. = FALSE)
    }
    for (key in join_keys) {
      if (!identical(as.character(exposure$table[[key]][idx]),
        as.character(context$svy_baseline[[key]][ids]))) {
        stop("Weather exposure/survey identity mismatch: ", key, call. = FALSE)
      }
    }
    if (!is.null(pipeline$weight) && "weight" %in% names(context$svy_baseline) &&
      !identical(pipeline$weight, context$svy_baseline$weight[ids])) {
      stop("Prediction/survey weight mismatch.", call. = FALSE)
    }
    ts <- as.POSIXlt(exposure$table$timestamp[idx])
    if (!all(as.integer(ts$year + 1900L) == pipeline$sim_year) ||
      !all(as.integer(ts$mon + 1L) == exposure$table$int_month[idx])) {
      stop("Weather anchor does not match simulation year/month.", call. = FALSE)
    }
    # Remember the structure only after every structural check has passed.
    if (is.environment(cache) && !is.null(structure)) {
      cache$validated_structure <- structure
    }
  }
  for (v in context$weather_vars) {
    x <- exposure$table[[v]][idx]
    baseline <- context$svy_baseline[[v]]
    if (is.factor(baseline)) {
      if (!is.factor(x) || any(!as.character(x) %in% levels(baseline))) {
        stop("Unknown or invalid weather category: ", v, call. = FALSE)
      }
    } else if (!is.numeric(x) || any(!is.finite(x))) {
      stop("Nonfinite or nonnumeric weather exposure: ", v, call. = FALSE)
    }
  }
  exposure
}

# Household-level channel changes in outcome units. For log outcomes this is
# the same conversion as `.decomposition_outcome_channels()`.
#
# P2-3: the shock-responsive transfer (`ch$delta_sp_shock`, zero without a shock
# program) is its own last column. The first column is then the static main
# effect, and main + shock is the old combined Main: repositioning, interaction
# and total are computed from the combined `delta_main`, so they do not change.
.policy_level_channels <- function(ch, is_log, baseline) {
  shock <- ch$delta_sp_shock %||% 0
  if (!is_log) {
    return(cbind(ch$delta_main - shock, ch$delta_res1, ch$delta_res2, ch$delta_total, shock))
  }
  if (!is.null(ch$sp_level)) {
    # DOC-11: the cash transfer is a level amount, not scaled by the other
    # channels. Its level is baseline * (exp(log shift) - 1), computed against
    # the same predicted level as the log shift, so it equals T where a
    # prediction exists and the observed-baseline value elsewhere.
    cash_static <- (exp(ch$delta_sp - shock) - 1) * baseline
    cash_shock <- (exp(shock) - 1) * baseline
    covar <- ch$delta_main_covar
    return(cbind(
      (exp(covar) - 1) * baseline + cash_static,
      exp(covar) * (exp(ch$delta_res1) - 1) * baseline,
      exp(covar + ch$delta_res1) * (exp(ch$delta_res2) - 1) * baseline,
      (exp(covar + ch$delta_res1 + ch$delta_res2) - 1) * baseline + cash_static + cash_shock,
      cash_shock
    ))
  }
  main_static <- (exp(ch$delta_main - shock) - 1) * baseline
  cbind(
    main_static,
    exp(ch$delta_main) * (exp(ch$delta_res1) - 1) * baseline,
    exp(ch$delta_main + ch$delta_res1) * (exp(ch$delta_res2) - 1) * baseline,
    (exp(ch$delta_main + ch$delta_res1 + ch$delta_res2) - 1) * baseline,
    (exp(ch$delta_main) - 1) * baseline - main_static
  )
}

.policy_annual_channels <- function(pipeline, prepared, run_identity,
                                    rows = seq_along(pipeline$y_point),
                                    owner = NULL) {
  if (!is.environment(prepared) || !environmentIsLocked(prepared)) {
    stop("Invalid prepared annual channel source.", call. = FALSE)
  }
  context <- prepared$context
  .validate_run_decomposition_context(context, run_identity)
  if (!identical(prepared$run_identity, run_identity)) {
    stop("Annual channel run identity mismatch.", call. = FALSE)
  }
  exposure <- .validate_policy_annual_exposure(pipeline, context, owner)
  if (!is.numeric(rows) || anyNA(rows) || any(rows != as.integer(rows)) ||
    any(rows < 1 | rows > length(pipeline$y_point)) || anyDuplicated(rows)) {
    stop("Invalid annual channel row selection.", call. = FALSE)
  }
  .policy_annual_channel_block(pipeline, prepared, exposure, rows,
    sp_dynamic = .policy_sp_dynamic(pipeline, prepared, exposure))
}

# Shock-responsive transfer of one pipeline on the outcome's model scale, one
# value per prediction row; NULL when the run has no shock program. Every
# consumer of the correction computes it from the same pure function, once per
# pipeline and before any chunk or year loop (P1-6).
.policy_sp_dynamic <- function(pipeline, prepared, exposure) {
  .policy_sp_shock_eval(pipeline, prepared, exposure)$model
}

# The trigger state, the stored-scale transfer and its model-scale conversion
# for one pipeline (all NULL without a shock program).
.policy_sp_shock_eval <- function(pipeline, prepared, exposure) {
  plan <- prepared$shock
  if (is.null(plan)) return(list(state = NULL, stored = NULL, model = NULL))
  context <- prepared$context
  state <- sp_shock_pipeline_state(plan, pipeline, exposure)
  stored <- sp_shock_pipeline_transfer(plan, pipeline, exposure, state)
  ppp <- .outcome_ppp(context$svy_baseline)[pipeline$svy_row_id]
  nominal <- outcome_level_scale(stored, context$so, ppp)
  # Welfare effectiveness of the payment (timing design, P2-7); cost and the
  # reach figures keep the nominal amount
  list(state = state, stored = stored, nominal = nominal,
    model = if (is.null(state$effect)) nominal else nominal * state$effect)
}

# Internal hot loop: callers validate the immutable source and whole mapping
# once before consuming bounded blocks. Public adapter calls remain strict.
# `sp_dynamic` (per prediction row of the whole pipeline, model scale) adds a
# shock-responsive transfer; NULL leaves the block exactly as before.
.policy_annual_channel_block <- function(pipeline, prepared, exposure, rows,
                                         sp_dynamic = NULL) {
  ids <- pipeline$svy_row_id[rows]
  idx <- exposure$row_index[rows]
  r1 <- r2 <- numeric(length(rows))
  # Step 2 anchors predictions to observed welfare (y_obs + beta (W_t - W_svy)),
  # so the weather terms act on the change from each household's survey-time
  # weather, not on the absolute level (R2-BUG-06).
  svy <- prepared$context$svy_baseline
  for (v in names(prepared$products)) {
    p <- prepared$products[[v]]
    x <- exposure$table[[v]][idx]
    x0 <- svy[[v]][ids]
    if (is.null(p$categories)) {
      x <- x - x0
      r1 <- r1 + p$repositioning[ids, 1L] * x
      r2 <- r2 + p$interaction[ids, 1L] * x
    } else {
      lookup <- cbind(ids, match(as.character(x), p$categories))
      lookup0 <- cbind(ids, match(as.character(x0), p$categories))
      r1 <- r1 + p$repositioning[lookup] - p$repositioning[lookup0]
      r2 <- r2 + p$interaction[lookup] - p$interaction[lookup0]
    }
  }
  # R2-BUG-07: a log-outcome transfer is a level amount, so its log effect is
  # taken against the predicted year-t level, not the observed baseline. Rows
  # without a finite prediction keep the observed-baseline value.
  delta_sp <- prepared$delta_sp[ids]
  y_t <- as.numeric(pipeline$y_point[rows])
  is_log <- identical(prepared$context$so$transform %||% "", "log")
  # DOC-11: the level amount paid, kept beside its log shift so that the
  # aggregation can add it after the residual and after the repositioning terms
  # (NULL for a level outcome). The quantile model has no residual term, but its
  # repositioning scales the market part of welfare, not the cash.
  track_sp <- is_log
  sp_level <- if (track_sp) numeric(length(rows))
  sp_level_shock <- NULL
  if (is_log) {
    transfer <- as.numeric(prepared$context$sp_transfer)[ids]
    ok <- is.finite(y_t) & is.finite(transfer)
    delta_sp[ok] <- ifelse(transfer[ok] == 0, 0,
      log(pmax(exp(y_t[ok]) + transfer[ok], 1e-10)) - y_t[ok])
    if (track_sp) sp_level[ok] <- transfer[ok]
  }
  if (!is.null(sp_dynamic)) {
    # Own vector, added into delta_sp (and so delta_main and delta_total): the
    # Phase 2 channel split is then presentational. RIF repositioning does not
    # see this transfer (plan section 4.3). Rows with no finite prediction use
    # the observed baseline level, as the static transfer does above.
    transfer <- sp_dynamic[rows]
    delta_sp_shock <- sp_dynamic_effect(y_t, transfer, is_log)
    missing <- is.na(delta_sp_shock)
    if (track_sp) {
      sp_level_shock <- ifelse(missing | !is.finite(transfer), 0, transfer)
      sp_level <- sp_level + sp_level_shock
    }
    if (any(missing)) {
      fallback <- if (is_log) {
        level_base <- as.numeric(prepared$context$y_level_baseline)[ids][missing]
        sp_dynamic_effect(log(pmax(level_base, 1e-10)), transfer[missing], TRUE)
      } else {
        NA_real_
      }
      delta_sp_shock[missing] <- ifelse(is.finite(fallback), fallback, 0)
    }
    delta_sp <- delta_sp + delta_sp_shock
  }
  covar <- prepared$delta_main_covar[ids]
  main <- delta_sp + covar
  out <- list(status = "ok", delta_sp = delta_sp,
    delta_main_covar = covar, delta_main = main,
    delta_res1 = r1, delta_res2 = r2, delta_total = main + r1 + r2,
    prediction_row_id = exposure$prediction_row_id[rows],
    repositioning_modeled = prepared$repositioning_modeled,
    interaction_included = prepared$interaction_included,
    correction_version = prepared$correction_version)
  if (!is.null(sp_dynamic)) out$delta_sp_shock <- delta_sp_shock
  if (track_sp) {
    out$sp_level <- sp_level
    out$sp_level_shock <- sp_level_shock
  }
  out
}

.apply_policy_annual_pipeline <- function(pipeline, prepared, run_identity,
                                          scenario = NULL, member = NULL,
                                          year_range = c(NA_integer_, NA_integer_),
                                          chunk_size = 100000L, owner = NULL,
                                          exposure_cache = NULL) {
  .validate_run_decomposition_context(prepared$context, run_identity)
  if (!identical(prepared$run_identity, run_identity)) {
    stop("Annual channel run identity mismatch.", call. = FALSE)
  }
  year_range <- suppressWarnings(as.integer(as.character(year_range)))
  if (length(year_range) != 2L) year_range <- c(NA_integer_, NA_integer_)
  if (is.null(pipeline$y_point)) stop("Missing baseline prediction pipeline.", call. = FALSE)
  exposure <- .validate_policy_annual_exposure(pipeline, prepared$context,
    owner, exposure_cache)
  n <- length(pipeline$y_point)
  years <- sort(unique(pipeline$sim_year))
  channel_stats <- decile_stats <- cell_stats <- NULL
  stat_names <- as.vector(rbind(paste0("sum_", .compact_decomp_channels),
    paste0("weight_", .compact_decomp_channels)))
  baseline_stat_names <- c("sum_baseline_y_point", "weight_baseline_y_point",
    "sum_baseline_level", "weight_baseline_level",
    as.vector(rbind(paste0("sum_", .compact_level_channels),
      paste0("weight_", .compact_level_channels))))
  stat_names <- c(stat_names, baseline_stat_names)
  is_log_outcome <- identical(prepared$context$so$transform %||% "", "log")
  accumulate <- function(current, values, group, n_groups) {
    if (is.null(current)) current <- matrix(0, n_groups, ncol(values))
    grouped <- rowsum(values, group, reorder = FALSE)
    keys <- as.integer(rownames(grouped))
    current[keys, ] <- current[keys, , drop = FALSE] + grouped
    current
  }
  out <- pipeline
  # DOC-11: the transfer paid per row and its log shift, for the aggregation to
  # add it after the residual (and, for the quantile model, after repositioning).
  track_sp <- is_log_outcome
  sp_level <- sp_log <- if (track_sp) numeric(n)
  shock <- .policy_sp_shock_eval(pipeline, prepared, exposure)
  sp_dynamic <- shock$model
  for (start in seq.int(1L, n, by = chunk_size)) {
    rows <- seq.int(start, min(n, start + chunk_size - 1L))
    ch <- .policy_annual_channel_block(pipeline, prepared, exposure, rows, sp_dynamic)
    if (any(!is.finite(ch$delta_total))) {
      stop("Nonfinite annual policy correction.", call. = FALSE)
    }
    out$y_point[rows] <- pipeline$y_point[rows] + ch$delta_total
    if (track_sp) {
      sp_level[rows] <- ch$sp_level
      sp_log[rows] <- ch$delta_sp
    }
    if (!is.null(scenario)) {
      weights <- if (is.null(pipeline$weight)) rep(1, length(rows)) else pipeline$weight[rows]
      valid <- is.finite(weights) & weights > 0
      weights[!valid] <- 0
      # P2-3: Main and the cash-transfer channel are the static ones; the
      # shock-responsive transfer is its own (last) channel. Static + shock is
      # the old combined value, and the total is unchanged.
      shock_ch <- ch$delta_sp_shock %||% 0
      values <- cbind(ch$delta_total, ch$delta_main - shock_ch, ch$delta_sp - shock_ch,
        ch$delta_main_covar, ch$delta_res1 + ch$delta_res2, ch$delta_res1, ch$delta_res2,
        shock_ch)
      stats <- matrix(0, length(rows), length(stat_names))
      channel_count <- length(.compact_decomp_channels) * 2L
      stats[, seq.int(1L, channel_count, 2L)] <- values * weights
      stats[, seq.int(2L, channel_count, 2L)] <- weights
      baseline_value <- as.numeric(pipeline$y_point[rows])
      baseline_weight <- weights
      baseline_weight[!is.finite(baseline_value)] <- 0
      baseline_value[!is.finite(baseline_value)] <- 0
      stats[, channel_count + 1L] <- baseline_value * baseline_weight
      stats[, channel_count + 2L] <- baseline_weight
      # Outcome-level baseline (back-transformed for log outcomes): the annual
      # mean ranked by the adverse-year rule, as in Step 2 and Step 3 results.
      level_value <- if (is_log_outcome) exp(baseline_value) else baseline_value
      level_weight <- baseline_weight
      level_weight[!is.finite(level_value)] <- 0
      level_value[!is.finite(level_value)] <- 0
      stats[, channel_count + 3L] <- level_value * level_weight
      stats[, channel_count + 4L] <- level_weight
      # Outcome-unit channels, converted household by household against the
      # observed baseline outcome (the level each log effect was computed on).
      # Averaging log effects first and converting afterwards is biased.
      # CR-BUG-02: observed baseline on the outcome-currency level scale (the
      # model scale of the log effects), not the stored 2021 PPP column.
      # R2-BUG-07: and against the predicted year-t level where one exists, so
      # level channels reconcile with the metric states.
      level_base <- as.numeric(prepared$context$y_level_baseline)[pipeline$svy_row_id[rows]]
      if (is_log_outcome) {
        predicted <- exp(as.numeric(pipeline$y_point[rows]))
        use <- is.finite(predicted)
        level_base[use] <- predicted[use]
      }
      lvl <- .policy_level_channels(ch, is_log_outcome, level_base)
      lvl_weight <- weights * is.finite(lvl)
      lvl[!is.finite(lvl)] <- 0
      for (k in seq_along(.compact_level_channels)) {
        stats[, channel_count + 4L + 2L * k - 1L] <- lvl[, k] * lvl_weight[, k]
        stats[, channel_count + 4L + 2L * k] <- lvl_weight[, k]
      }
      year_id <- match(pipeline$sim_year[rows], years)
      deciles <- prepared$context$baseline_deciles[pipeline$svy_row_id[rows]]
      decile_code <- integer(length(rows))
      in_decile <- is.finite(deciles) & deciles >= 1 & deciles <= 10
      decile_code[in_decile] <- as.integer(deciles[in_decile])
      # One grouped sum per chunk over (year, decile) cells, decile 0 for rows
      # without a baseline decile; the year totals are summed from the cells
      # after the loop instead of scanning the chunk a second time.
      cell_stats <- accumulate(cell_stats, cbind(stats, 1, weights),
        (year_id - 1L) * 11L + decile_code + 1L, length(years) * 11L)
    }
  }
  if (track_sp && any(sp_level != 0)) {
    out$sp_level <- sp_level
    out$sp_log <- sp_log
  }
  # DOC-12: the policy arm's coefficient uncertainty includes the policy terms
  policy_loading <- .policy_arm_loading(pipeline, prepared, exposure, chunk_size)
  if (!is.null(policy_loading)) out$F_loading <- policy_loading
  if (!is.null(cell_stats)) {
    channel_stats <- rowsum(cell_stats[, seq_along(stat_names), drop = FALSE],
      rep(seq_along(years), each = 11L))
    rownames(channel_stats) <- NULL
    decile_stats <- cell_stats[rep(c(FALSE, rep(TRUE, 10L)), length(years)), , drop = FALSE]
  }
  make_table <- function(stats, decile = FALSE) {
    if (is.null(stats)) return(data.frame())
    if (decile) {
      keys <- which(stats[, ncol(stats) - 1L] > 0)
      stats <- stats[keys, , drop = FALSE]
      sim_year <- years[(keys - 1L) %/% 10L + 1L]
    } else sim_year <- years
    colnames(stats) <- c(stat_names, if (decile) c("n_households", "weighted_population"))
    # Empty positive-weight groups match the technical reducer's unavailable state.
    for (j in seq.int(2L, length(stat_names), 2L)) {
      zero <- stats[, j] == 0
      stats[zero, c(j - 1L, j)] <- NA_real_
    }
    tbl <- data.frame(scenario = scenario, sim_year = sim_year,
      year_start = year_range[[1L]], year_end = year_range[[2L]], stats,
      engine = prepared$context$engine, is_rif = prepared$repositioning_modeled,
      member = member, correction_version = prepared$correction_version,
      scope = "production_prediction_rows", uncertainty = "central_only")
    if (decile) {
      tbl$decile <- as.integer((keys - 1L) %% 10L + 1L)
      tbl$n_households <- as.integer(tbl$n_households)
    }
    tbl
  }
  compact <- if (!is.null(scenario)) list(
    channel = make_table(channel_stats), decile = make_table(decile_stats, TRUE),
    metadata = list(scenario = scenario, year_start = year_range[[1L]], year_end = year_range[[2L]]),
    engine = prepared$context$engine, is_rif = prepared$repositioning_modeled
  ) else NULL
  if (!is.null(compact)) {
    compact$channel_summary$baseline_annual <- ifelse(
      is.finite(compact$channel_summary$weight_baseline_y_point) & compact$channel_summary$weight_baseline_y_point > 0,
      compact$channel_summary$sum_baseline_y_point / compact$channel_summary$weight_baseline_y_point,
      NA_real_)
    compact$decile_summary$baseline_annual <- ifelse(
      is.finite(compact$decile_summary$weight_baseline_y_point) & compact$decile_summary$weight_baseline_y_point > 0,
      compact$decile_summary$sum_baseline_y_point / compact$decile_summary$weight_baseline_y_point,
      NA_real_)
  }
  out$policy_correction <- list(version = prepared$correction_version,
    run_identity = run_identity, exposure_source = "step2_prediction_row_mapping",
    n_prediction_rows = n, n_exposure_anchors = nrow(exposure$table),
    scope = "production_prediction_rows", uncertainty = "baseline_X_gradient")
  result <- list(pipeline = out, compact = compact)
  if (!is.null(shock$state)) {
    # Run outputs of the shock program (P1-7), from the baseline predictions
    rows <- sp_shock_pipeline_rows(
      prepared$shock, pipeline, exposure, shock$state, shock$stored,
      transfer_model = shock$nominal
    )
    scenario_name <- scenario %||% "Scenario"
    member_name <- member %||% "Member"
    cells <- attr(rows, "cells")
    attr(rows, "cells") <- NULL
    result$shock_reach <- attr(rows, "reach")
    attr(rows, "reach") <- NULL
    result$shock <- cbind(scenario = scenario_name, member = member_name, rows)
    # Per-cell loss data, so the loss-event share can be changed without a re-run
    if (!is.null(cells)) {
      result$shock_cells <- cbind(scenario = scenario_name, member = member_name, cells)
    }
    # Survey rows paid in at least one simulated year (diagnostics "treated")
    paid <- logical(length(prepared$shock$per_household))
    paid[as.integer(pipeline$svy_row_id)[shock$stored > 0]] <- TRUE
    result$shock_paid <- paid
    # Mean payment in the years a row was paid: the "amount of one activation"
    # for a budget that varies with the modelled loss (P2-6)
    pos <- is.finite(shock$stored) & shock$stored > 0
    paid_mean <- numeric(length(paid))
    if (any(pos)) {
      ids_pos <- as.integer(pipeline$svy_row_id)[pos]
      sums <- rowsum(shock$stored[pos], ids_pos)
      n_pos <- rowsum(rep(1, sum(pos)), ids_pos)
      paid_mean[as.integer(rownames(sums))] <- sums[, 1L] / n_pos[, 1L]
    }
    result$shock_paid_mean <- paid_mean
  }
  result
}

# Deliberately slow reference for tests/benchmarks only: evaluate the original
# central kernels against each row's exact exposures, then select its household.
# Regular-only: it reads the static `context$sp_transfer` and has no shock
# argument, so it does not model the dynamic shock-responsive transfer
# (`delta_sp_shock`). Shock parity is covered by test-sp-shock-correction.R.
.policy_annual_channels_reference <- function(pipeline, context, run_identity,
                                              owner = NULL) {
  .validate_run_decomposition_context(context, run_identity)
  endpoint <- .policy_annual_channel_status(context)
  if (!identical(endpoint$status, "ok")) return(endpoint)
  exposure <- .validate_policy_annual_exposure(pipeline, context, owner)
  columns <- c("delta_sp", "delta_main_covar", "delta_main", "delta_res1", "delta_res2", "delta_total")
  out <- setNames(lapply(columns, function(x) numeric(length(pipeline$y_point))), columns)
  for (i in seq_along(pipeline$y_point)) {
    hazards <- setNames(lapply(context$weather_vars, function(v) {
      rep(exposure$table[[v]][exposure$row_index[i]], context$n)
    }), context$weather_vars)
    ch <- .policy_explicit_channels(context, hazards)
    # Weather channels are linear in the exposure: evaluate at the survey-time
    # weather too and difference (R2-BUG-06).
    anchor <- .policy_explicit_channels(context, setNames(
      lapply(context$weather_vars, function(v) context$svy_baseline[[v]]),
      context$weather_vars))
    ch$delta_res1 <- ch$delta_res1 - anchor$delta_res1
    ch$delta_res2 <- ch$delta_res2 - anchor$delta_res2
    # DOC-10: the main effect is the effect at the interview weather
    ch$delta_main <- ch$delta_main + anchor$delta_res1 + anchor$delta_res2
    ch$delta_main_covar <- ch$delta_main_covar + anchor$delta_res1 + anchor$delta_res2
    row <- pipeline$svy_row_id[i]
    y_t <- pipeline$y_point[i]
    transfer <- as.numeric(context$sp_transfer)[row]
    if (identical(context$so$transform %||% "", "log") && is.finite(y_t) &&
      is.finite(transfer)) {
      # R2-BUG-07: transfer effect against the predicted year-t level.
      sp <- if (transfer == 0) 0 else log(pmax(exp(y_t) + transfer, 1e-10)) - y_t
      ch$delta_main[row] <- ch$delta_main[row] - ch$delta_sp[row] + sp
      ch$delta_sp[row] <- sp
    }
    ch$delta_total <- ch$delta_main + ch$delta_res1 + ch$delta_res2
    for (v in columns) out[[v]][i] <- ch[[v]][row]
  }
  c(list(status = "ok"), out)
}

# Cumulative states in order, then the contributions between them. P2-3: the
# shock-responsive transfer has its own state and contribution between the
# static main effect and repositioning; without a shock program `after_main`
# equals `after_static_main` and `sp_shock` is 0, so `main + sp_shock` is the
# old combined Main and every other value is unchanged.
.policy_metric_fields <- c("baseline", "after_static_main", "after_main",
  "after_repositioning", "policy", "main", "sp_shock", "repositioning",
  "interaction", "resilience", "total")
.policy_metric_n_states <- 5L
.policy_metric_tolerance <- 1e-8

.policy_metric_contributions <- function(levels) {
  levels$main <- levels$after_static_main - levels$baseline
  levels$sp_shock <- levels$after_main - levels$after_static_main
  levels$repositioning <- levels$after_repositioning - levels$after_main
  levels$interaction <- levels$policy - levels$after_repositioning
  levels$resilience <- levels$repositioning + levels$interaction
  levels$total <- levels$policy - levels$baseline
  levels
}

# One summary operator for every cumulative state and contribution. Models with
# unequal year counts still receive equal weight; survey weights act upstream.
.policy_metric_summary <- function(annual, scenario) {
  models <- split(annual, annual$model_id)
  means <- lapply(models, function(x) colMeans(x[, .policy_metric_fields, drop = FALSE]))
  values <- as.list(colMeans(do.call(rbind, means)))
  data.frame(scenario = scenario, values, n_models = length(models),
    n_model_years = nrow(annual), n_years = min(vapply(models, nrow, integer(1))),
    center_method = "equal_model_mean", scope = "production_prediction_rows")
}

.policy_metric_tails <- function(annual, scenario, adverse_tail,
                                 baseline_series = NULL, required_models = NULL) {
  states <- .policy_metric_fields[seq_len(.policy_metric_n_states)]
  annual_models <- if (is.data.frame(annual) && "model_id" %in% names(annual)) {
    split(annual, as.character(annual$model_id))
  } else list()
  required_models <- as.character(required_models %||% names(annual_models))
  required_models <- unique(required_models[!is.na(required_models) & nzchar(required_models)])
  baseline_models <- if (is.list(baseline_series) && !is.null(baseline_series$vals)) {
    baseline_series$model_ids
  } else names(annual_models)
  model_ids <- unique(c(required_models, as.character(baseline_models)))
  support_rows <- list()
  model_rows <- list()
  scenario_rows <- list()
  for (p in unname(RP_LOW)) {
    supported_levels <- list()
    support_ok <- logical(length(model_ids))
    for (i in seq_along(model_ids)) {
      id <- model_ids[[i]]
      annual_model <- annual_models[[id]]
      source_values <- NULL
      source_years <- NULL
      source_name <- "reconstructed_baseline_annual_metric"
      if (!is.null(baseline_series) && !is.null(baseline_series$vals) && id %in% baseline_series$model_ids) {
        row <- match(id, baseline_series$model_ids)
        source_values <- as.numeric(baseline_series$vals[row, ])
        source_years <- suppressWarnings(as.numeric(baseline_series$sim_years))
        source_name <- "results_baseline_endpoint"
      } else if (!is.null(annual_model)) {
        source_values <- annual_model$baseline
        source_years <- annual_model$sim_year
      }
      support <- if (is.null(source_values)) {
        adverse_year_support(numeric(), numeric(), p, adverse_tail)
      } else adverse_year_support(source_values, source_years, p, adverse_tail)
      support_row <- as.data.frame(c(list(scenario = scenario, model_id = id), support),
        stringsAsFactors = FALSE)
      support_row$adverse_basis <- "baseline_selected_metric"
      support_row$scope <- "baseline_anchored"
      support_row$support_source <- source_name
      support_rows[[length(support_rows) + 1L]] <- support_row
      state_result <- setNames(as.list(rep(NA_real_, length(states))), states)
      status <- support$status
      reason <- support$reason
      if (identical(status, "ok") && !is.null(annual_model)) {
        if (anyDuplicated(annual_model$sim_year)) {
          status <- "unavailable"; reason <- "Duplicate model/year annual metric keys."
        } else {
          applied <- lapply(states, function(state) apply_adverse_year_support(
            annual_model[[state]], annual_model$sim_year, support))
          names(applied) <- states
          bad <- states[!vapply(applied, function(x) identical(x$status, "ok"), logical(1))]
          if (length(bad)) {
            status <- "unavailable"
            reason <- paste0("Selected baseline support unavailable for state(s): ", paste(bad, collapse = ", "), ".")
          } else {
            state_result <- lapply(applied, `[[`, "value")
            if (!is.null(baseline_series) && identical(source_name, "results_baseline_endpoint")) {
              parity <- abs(state_result$baseline - support$baseline_value) <=
                .policy_metric_tolerance * max(1, abs(support$baseline_value))
              if (!parity) {
                status <- "unavailable"; reason <- "Reconstructed annual baseline metric does not match Results endpoint."
              }
            }
          }
        }
      } else if (identical(status, "ok")) {
        status <- "unavailable"; reason <- "Annual state channels unavailable at baseline support."
      }
      contribution <- .policy_metric_contributions(state_result)
      model_row <- as.data.frame(c(list(scenario = scenario, model_id = id,
        probability = p, return_period = 1 / p), support[
          c("baseline_value", "rank_lo", "rank_hi", "year_lo", "year_hi", "weight_lo", "weight_hi",
            "n_years_total", "n_years_finite", "n_years_excluded", "min_years", "quantile_method", "tie_method")
        ], contribution), stringsAsFactors = FALSE)
      model_row$status <- status; model_row$reason <- reason
      model_row$adverse_basis <- "baseline_selected_metric"
      model_row$scope <- "baseline_anchored"
      model_rows[[length(model_rows) + 1L]] <- model_row
      support_ok[[i]] <- identical(status, "ok")
      if (support_ok[[i]]) supported_levels[[id]] <- contribution
    }
    ok <- length(model_ids) > 0L && length(support_ok) == length(model_ids) && all(support_ok)
    if (ok) {
      means <- lapply(supported_levels, function(x) unlist(x[states], use.names = TRUE))
      levels <- as.list(colMeans(do.call(rbind, means)))
      row <- as.data.frame(c(list(scenario = scenario), .policy_metric_contributions(levels)),
        stringsAsFactors = FALSE)
      row$status <- "ok"; row$reason <- ""
    } else {
      reasons <- unique(vapply(model_rows[(length(model_rows) - length(model_ids) + 1L):length(model_rows)],
        function(x) as.character(x$reason[[1L]]), character(1)))
      row <- as.data.frame(c(list(scenario = scenario),
        setNames(as.list(rep(NA_real_, length(.policy_metric_fields))), .policy_metric_fields)),
        stringsAsFactors = FALSE)
      row$status <- "unavailable"
      row$reason <- paste(reasons[nzchar(reasons)], collapse = " ")
      if (!nzchar(row$reason)) row$reason <- "One or more required models lack baseline support or a selected state value."
    }
    row$probability <- p; row$return_period <- 1 / p
    row$scope <- "baseline_anchored"
    row$adverse_basis <- "baseline_selected_metric"
    row$center_method <- if (identical(scenario, "Historical")) "single_historical" else "equal_model_mean"
    row$ensemble_center <- row$center_method
    row$quantile_method <- "rank_interp_n_p_plus_half"
    row$tie_method <- "value_then_sim_year_ascending"
    row$n_models <- length(model_ids)
    row$n_supported_models <- sum(support_ok)
    row$n_model_years <- if (length(annual_models)) sum(vapply(annual_models, nrow, integer(1))) else 0L
    scenario_rows[[length(scenario_rows) + 1L]] <- row
  }
  out <- dplyr::bind_rows(scenario_rows)
  attr(out, "adverse_support") <- dplyr::bind_rows(support_rows)
  attr(out, "adverse_by_model") <- dplyr::bind_rows(model_rows)
  out
}

# Build a data frame from a list of equal-shape scalar rows in one pass, instead
# of one data.frame() per row (R2-PERF-06b). Empty input matches bind_rows().
.policy_rows_to_frame <- function(rows) {
  if (!length(rows)) return(dplyr::bind_rows(rows))
  columns <- names(rows[[1L]])
  frame <- data.frame(lapply(stats::setNames(columns, columns), function(column) {
    unlist(lapply(rows, `[[`, column), use.names = FALSE)
  }), stringsAsFactors = FALSE, check.names = FALSE)
  dplyr::bind_rows(frame)
}

# Residual draws depend only on the effective mode, the training residuals, the
# row ids and the year seed, so members of one scenario (same rows) share them.
# `cache` holds the lookup and variance built once per training frame and the
# draw of each year with the ids and length it was drawn for; a different frame,
# mode, id vector or length is a miss, never a stale hit.
.policy_metric_residuals <- function(cache, effective, train_aug, id_col, ids, n,
                                     year, seed = WISEAPP_DEFAULT_SEED) {
  if (!isTRUE(cache$ready) || !identical(cache$train_aug, train_aug) ||
    !identical(cache$id_col, id_col)) {
    cache$ready <- TRUE
    cache$train_aug <- train_aug
    cache$id_col <- id_col
    cache$lookup <- .residual_lookup(train_aug, id_col)
    cache$draws <- list()
  }
  key <- as.character(year)
  hit <- cache$draws[[key]]
  if (!is.null(hit) && identical(hit$mode, effective) && identical(hit$n, n) &&
    identical(hit$ids, ids) && identical(hit$seed, seed)) {
    return(hit$value)
  }
  value <- draw_residuals_vec(effective, train_aug, n, ids, id_col,
    seed = wise_seed(seed, "residual", year),
    resid_lookup = cache$lookup)
  cache$draws[[key]] <- list(
    mode = effective, n = n, ids = ids, seed = seed, value = value
  )
  value
}

.policy_metric_pipeline <- function(baseline, policy, prepared, method, pov_line,
                                    requested_residuals, shared_baseline, shared_policy,
                                    scenario, member, owner = NULL,
                                    exposure_cache = NULL,
                                    validation_cache = NULL,
                                    residual_cache = NULL,
                                    seed = WISEAPP_DEFAULT_SEED) {
  context <- prepared$context
  residual_cache <- residual_cache %||% new.env(parent = emptyenv())
  # R2-PERF-06b: the exposure checks are a per-row scan of every member. Within
  # one run (the cache is dropped when any run input changes) a member that has
  # passed once only needs its exposure rebuilt, not revalidated.
  validation_key <- paste(scenario, member, sep = "\r")
  if (is.environment(validation_cache) && isTRUE(validation_cache[[validation_key]])) {
    exposure <- step2_exposure_resolve(baseline, owner, exposure_cache)
    if (is.null(exposure) || !identical(exposure$status, "ok")) {
      stop("Exact prediction-row weather exposure mapping unavailable.", call. = FALSE)
    }
  } else {
    exposure <- .validate_policy_annual_exposure(baseline, context, owner, exposure_cache)
    if (is.environment(validation_cache)) validation_cache[[validation_key]] <- TRUE
  }
  # weather_raw is part of the alignment: schema-2 exposure tables are rebuilt
  # from it, so equal recipes must also share the same weather.
  for (field in c("svy_row_id", "sim_year", "weight", "id_vec", "weather_exposure",
    "weather_raw")) {
    if (!identical(baseline[[field]], policy[[field]])) {
      stop("Baseline/policy row alignment mismatch: ", field, call. = FALSE)
    }
  }
  if (length(baseline$y_point) != length(policy$y_point) ||
    !identical(is.na(baseline$y_point), is.na(policy$y_point))) {
    stop("Baseline/policy prediction missingness mismatch.", call. = FALSE)
  }
  correction <- policy$policy_correction
  if (!identical(correction$version, prepared$correction_version) ||
    !identical(correction$run_identity, prepared$run_identity)) {
    stop("Policy correction version/run identity mismatch.", call. = FALSE)
  }
  bctx <- step2_pipeline_context(baseline, shared_baseline)
  pctx <- step2_pipeline_context(policy, shared_policy)
  if (!identical(bctx$train_aug, pctx$train_aug) || !identical(bctx$id_col, pctx$id_col)) {
    stop("Baseline/policy residual context mismatch.", call. = FALSE)
  }
  effective <- requested_residuals
  if (is.null(bctx$train_aug) || !".resid" %in% names(bctx$train_aug)) effective <- "none"
  is_log <- isTRUE(context$so$transform == "log")
  aggregate <- resolve_agg_fn(method)
  years <- sort(unique(baseline$sim_year))
  sp_dynamic <- .policy_sp_dynamic(baseline, prepared, exposure)
  deciles <- prepared$context$baseline_deciles
  annual <- decile_annual <- mechanisms <- list()
  for (year in years) {
    all_rows <- which(baseline$sim_year == year)
    rows <- all_rows[!is.na(baseline$y_point[all_rows])]
    if (!length(rows)) next
    ch <- .policy_annual_channel_block(baseline, prepared, exposure, rows, sp_dynamic)
    y <- baseline$y_point[rows]
    target <- policy$y_point[rows]
    reconstructed <- y + ch$delta_total
    error <- max(abs(reconstructed - target))
    if (!all(is.finite(c(y, target, reconstructed))) ||
      !is.finite(error) || error > .policy_metric_tolerance * max(1, abs(target))) {
      stop("Final cumulative state does not match production policy predictions.", call. = FALSE)
    }
    # Same row mask, draw helper and year seed as .aggregation_prepare_pipeline;
    # reuse its invariant lookup/variance without hashing training data per year,
    # and the draw itself across members that share the rows.
    residual <- .policy_metric_residuals(residual_cache, effective,
      bctx$train_aug, bctx$id_col, baseline$id_vec[rows], length(rows), year,
      seed = seed)
    w <- if (!is.null(baseline$weight)) as.numeric(baseline$weight[rows]) else NULL
    row_deciles <- deciles[baseline$svy_row_id[rows]]
    n_states <- .policy_metric_n_states
    excluded <- integer(n_states)
    # States: baseline, + static main, + shock-responsive transfer, +
    # repositioning, + interaction. Without a shock program the third state is
    # the second, so it is not aggregated again.
    shock_ch <- ch$delta_sp_shock
    deltas <- list(rep(0, length(rows)),
      if (is.null(shock_ch)) ch$delta_main else ch$delta_main - shock_ch,
      shock_ch, ch$delta_res1, ch$delta_res2)
    # DOC-11: each state adds the transfers paid so far after the residual. The
    # static transfer joins at state 2, the shock-responsive one at state 3.
    sp_state <- if (is_log && !is.null(ch$sp_level)) {
      static_log <- ch$delta_sp - (shock_ch %||% 0)
      static_level <- ch$sp_level - (ch$sp_level_shock %||% 0)
      list(log = list(0, static_log, ch$delta_sp, ch$delta_sp, ch$delta_sp),
        level = list(0, static_level, ch$sp_level, ch$sp_level, ch$sp_level))
    }
    in_decile <- is.finite(row_deciles) & row_deciles >= 1 & row_deciles <= 10
    decile_codes <- integer(length(rows))
    decile_codes[in_decile] <- as.integer(row_deciles[in_decile])
    values <- numeric(n_states)
    state_values <- vector("list", n_states)
    # Whole-sample and per-decile values of the methods that need no sort come
    # from one pass per state (bit-identical to the resolver); other methods,
    # unweighted surveys and non-finite weights keep the per-call resolver.
    group_stats <- vector("list", n_states)
    for (j in seq_len(n_states)) {
      if (j == 3L && is.null(shock_ch)) {
        state_values[[j]] <- state_values[[2L]]
        values[j] <- values[2L]
        excluded[j] <- excluded[2L]
        next
      }
      if (j > 1L) y <- y + deltas[[j]]
      mu <- if (!is_log) {
        y + residual
      } else if (!is.null(sp_state)) {
        exp(y - sp_state$log[[j]] + residual) + sp_state$level[[j]]
      } else {
        exp(y + residual)
      }
      state_values[[j]] <- mu
      # `[<-` with list(): a NULL (not covered) must not delete the element
      group_stats[j] <- list(
        welfare_group_stats(mu, w, decile_codes, 10L, method, pov_line)
      )
      values[j] <- if (is.null(group_stats[[j]])) {
        aggregate(mu, w, pov_line)
      } else group_stats[[j]][[1L]]
      excluded[j] <- sum(!is.finite(mu) | (method == "avg_poverty" & mu <= 0))
    }
    names(values) <- .policy_metric_fields[seq_len(n_states)]
    annual[[length(annual) + 1L]] <- data.frame(scenario = scenario, member = member,
      model_id = member, sim_year = year, .policy_metric_contributions(as.list(values)),
      n_prediction_rows = length(all_rows), n_retained_rows = length(rows),
      n_excluded_rows = length(all_rows) - length(rows),
      excluded_baseline = excluded[1L], excluded_after_static_main = excluded[2L],
      excluded_after_main = excluded[3L],
      excluded_after_repositioning = excluded[4L], excluded_policy = excluded[5L],
      parity_error = error, requested_residuals = requested_residuals, effective_residuals = effective)
    valid_deciles <- sort(unique(row_deciles[in_decile]))
    decile_rows <- collapse::gsplit(which(in_decile), as.integer(row_deciles[in_decile]),
      use.g.names = FALSE)
    for (k in seq_along(valid_deciles)) {
      decile <- valid_deciles[[k]]
      selected <- decile_rows[[k]]
      decile_states <- vector("list", n_states)
      for (j in seq_len(n_states)) {
        decile_states[[j]] <- if (j == 3L && is.null(shock_ch)) {
          decile_states[[2L]]
        } else if (!is.null(group_stats[[j]])) {
          group_stats[[j]][[decile + 1L]]
        } else {
          aggregate(
            state_values[[j]][selected], if (is.null(w)) NULL else w[selected], pov_line
          )
        }
      }
      names(decile_states) <-.policy_metric_fields[seq_len(n_states)]
      decile_annual[[length(decile_annual) + 1L]] <- c(list(scenario = scenario,
        member = member, model_id = member, sim_year = year, decile = as.integer(decile)),
        .policy_metric_contributions(decile_states),
        list(n_prediction_rows = length(selected), n_retained_rows = length(selected)))
    }
    ids <- baseline$svy_row_id[rows]
    weighted_mean <- function(x) resolve_agg_fn("mean")(x, w, NULL)
    for (hazard in names(prepared$products)) {
      product <- prepared$products[[hazard]]
      for (j in seq_len(ncol(product$interaction))) {
        r1 <- product$repositioning[ids, j]
        r2 <- product$interaction[ids, j]
        mechanisms[[length(mechanisms) + 1L]] <- list(scenario = scenario,
          member = member, model_id = member, sim_year = year, hazard = hazard,
          category = if (is.null(product$categories)) NA_character_ else product$categories[j],
          contrast = if (is.null(product$categories)) "continuous_coefficient_change" else "fitted_reference_category_contrast",
          repositioning = if (prepared$repositioning_modeled) weighted_mean(r1) else NA_real_,
          interaction = if (prepared$interaction_included) weighted_mean(r2) else NA_real_,
          positive_repositioning_share = if (prepared$repositioning_modeled) weighted_mean(as.numeric(r1 > 0)) else NA_real_,
          negative_repositioning_share = if (prepared$repositioning_modeled) weighted_mean(as.numeric(r1 < 0)) else NA_real_,
          positive_interaction_share = if (prepared$interaction_included) weighted_mean(as.numeric(r2 > 0)) else NA_real_,
          negative_interaction_share = if (prepared$interaction_included) weighted_mean(as.numeric(r2 < 0)) else NA_real_,
          tau_pre = if (prepared$repositioning_modeled) weighted_mean(prepared$tau_i_pre[ids]) else NA_real_,
          tau_post = if (prepared$repositioning_modeled) weighted_mean(prepared$tau_i_post[ids]) else NA_real_,
          n_retained_rows = length(rows), weighted = !is.null(w),
          model_units = if (is_log) "log outcome units" else "model outcome units",
          weather_units = "exact fitted weather-input units; unit label unavailable",
          scope = "production_prediction_rows", scale = "model_scale")
      }
    }
  }
  list(annual = dplyr::bind_rows(annual), decile_annual = .policy_rows_to_frame(decile_annual),
    mechanisms = .policy_rows_to_frame(mechanisms))
}

# Pure run-owned calculation. Only small annual/summary tables escape; cumulative
# household vectors and residual preparations are temporary, one member/year.
.policy_metric_decomposition <- function(baseline_hist, policy_hist,
                                         baseline_scenarios, policy_scenarios,
                                         prepared, method, pov_line = NULL,
                                         requested_residuals = "original",
                                         endpoint_series_baseline = NULL,
                                         endpoint_series_policy = NULL,
                                         focus_scenario = NULL, analysis_unit = NULL,
                                         validation_cache = NULL) {
  so <- baseline_hist$so
  hist_name <- baseline_hist$hist_label %||% "Historical"
  focus_scenario <- focus_scenario %||% if (length(baseline_scenarios)) names(baseline_scenarios)[1L] else hist_name
  metadata <- metric_metadata(method, so, pov_line, analysis_unit,
    weighted = !is.null(baseline_hist$pipeline$weight))
  metadata$focus_scenario <- focus_scenario
  metadata$requested_residuals <- requested_residuals
  metadata$scale <- "metric_aware"
  metadata$uncertainty <- "central_only"
  metadata$component_order <- "main -> repositioning -> interaction"
  metadata$correction_version <- "row_aligned_annual_v1"
  metadata$exposure_source <- "step2_prediction_row_mapping"
  metadata$population_scope <- "fixed survey rows; canonical state-specific metric eligibility retained"
  metadata$eligibility_caveat <- if (method == "avg_poverty") {
    "Positive finite welfare eligibility is evaluated by the canonical metric in each state; this is not a fixed eligible subpopulation."
  } else metadata$caveat
  metadata$parity_tolerance <- .policy_metric_tolerance
  endpoint <- list()
  for (nm in intersect(names(endpoint_series_baseline), names(endpoint_series_policy))) {
    endpoint[[nm]] <- paired_model_year_effects(endpoint_series_baseline[[nm]]$out,
      endpoint_series_policy[[nm]]$out)
  }
  endpoint_summary <- dplyr::bind_rows(lapply(names(endpoint), function(nm) {
    paired_effect_summary(endpoint[[nm]], scenario = nm, center = "equal_model_mean")
  }))
  result <- list(status = "unavailable", reason = "Annual channel source unavailable.",
    annual = data.frame(), decile_annual = data.frame(), summary = data.frame(), return_period = data.frame(),
    adverse_support = data.frame(), adverse_by_model = data.frame(),
    mechanisms = list(), metadata = metadata, endpoint_summary = endpoint_summary, scenarios = list())
  status <- .policy_endpoint_status(so, if (is.environment(prepared)) prepared$context else NULL)
  if (!identical(status$status, "ok")) {
    result$status <- status$status; result$reason <- status$reason
    result$endpoint_summary <- data.frame()
    return(result)
  }
  if (!is.environment(prepared) || !environmentIsLocked(prepared)) return(result)
  result$metadata$run_identity <- prepared$run_identity
  result$metadata$repositioning_modeled <- prepared$repositioning_modeled
  result$metadata$interaction_included <- prepared$interaction_included
  validation <- tryCatch({
    .validate_run_decomposition_context(prepared$context, prepared$run_identity)
    .policy_annual_channel_status(prepared$context)
  }, error = function(e) list(status = "unavailable", reason = conditionMessage(e)))
  if (!identical(validation$status, "ok")) {
    result$status <- validation$status; result$reason <- validation$reason
    return(result)
  }
  owners_b <- c(setNames(list(list(pipelines = list(Historical = baseline_hist$pipeline),
    shared_context = baseline_hist$shared_context)), hist_name), baseline_scenarios)
  owners_p <- c(setNames(list(list(pipelines = list(Historical = policy_hist$pipeline),
    shared_context = policy_hist$shared_context)), hist_name), policy_scenarios)
  for (nm in names(owners_b)) {
    calculated <- tryCatch({
      b <- owners_b[[nm]]; p <- owners_p[[nm]]
      if (!length(b$pipelines) || !identical(names(b$pipelines), names(p$pipelines))) {
        stop("Baseline/policy member identity mismatch.", call. = FALSE)
      }
      exposure_cache <- new.env(parent = emptyenv())
      residual_cache <- new.env(parent = emptyenv())
      members <- lapply(names(b$pipelines), function(id) .policy_metric_pipeline(
        b$pipelines[[id]], p$pipelines[[id]], prepared, method, pov_line,
        requested_residuals, b$shared_context, p$shared_context, nm, id,
        owner = b, exposure_cache = exposure_cache,
        validation_cache = validation_cache, residual_cache = residual_cache,
        seed = .step2_run_seed(baseline_hist)))
      annual_full <- dplyr::bind_rows(lapply(members, `[[`, "annual"))
      decile_annual_full <- dplyr::bind_rows(lapply(members, `[[`, "decile_annual"))
      annual <- annual_full
      ep <- endpoint[[nm]]
      dropped <- 0L
      bmatrix <- if (!is.null(endpoint_series_baseline[[nm]]$out)) {
        by_model_matrix(endpoint_series_baseline[[nm]]$out)
      } else NULL
      required_models <- unique(c(names(b$pipelines), if (!is.null(bmatrix)) bmatrix$model_ids))
      if (!is.null(ep)) {
        ep <- ep[is.finite(ep$baseline) & is.finite(ep$policy) & is.finite(ep$effect), , drop = FALSE]
        key <- function(x) paste(x$model_id, x$sim_year, sep = "\r")
        if (anyDuplicated(key(annual_full)) || anyDuplicated(key(ep))) stop("Duplicate model/year aggregate keys.")
        index <- match(key(ep), key(annual_full))
        if (anyNA(index)) stop("Channel summary cannot cover Results endpoint support.")
        dropped <- nrow(annual_full) - nrow(ep)
        annual <- annual_full[index, , drop = FALSE]
        if (any(!is.finite(annual$baseline)) || any(abs(annual$baseline - ep$baseline) >
          .policy_metric_tolerance * pmax(1, abs(ep$baseline)))) {
          stop("Results endpoint baseline aggregate parity mismatch.")
        }
      }
      if (!nrow(annual_full)) {
        tails <- .policy_metric_tails(annual_full, nm, metadata$adverse_tail,
          baseline_series = bmatrix, required_models = required_models)
        return(list(status = "unavailable", reason = "No annual channel rows are available.",
          annual = data.frame(), annual_full = annual_full, decile_annual = data.frame(), summary = data.frame(),
          return_period = tails, adverse_support = attr(tails, "adverse_support"),
          adverse_by_model = attr(tails, "adverse_by_model"), mechanisms = data.frame()))
      }
      complete_expected <- if (nrow(annual)) {
        annual[apply(is.finite(as.matrix(annual[, .policy_metric_fields])), 1L, all), , drop = FALSE]
      } else annual
      decile_annual <- if (nrow(decile_annual_full) && nrow(complete_expected)) {
        key <- paste(complete_expected$model_id, complete_expected$sim_year, sep = "\r")
        decile_key <- paste(decile_annual_full$model_id, decile_annual_full$sim_year, sep = "\r")
        decile_annual_full[decile_key %in% key, , drop = FALSE]
      } else data.frame()
      decile_annual <- dplyr::bind_rows(lapply(split(decile_annual, decile_annual$model_id), function(rows) {
        rows$scenario <- nm
        rows
      }))
      summary <- if (nrow(complete_expected)) .policy_metric_summary(complete_expected, nm) else data.frame()
      summary$n_dropped_model_years <- dropped
      diagnostic <- dplyr::bind_rows(lapply(members, `[[`, "mechanisms"))
      diagnostic <- diagnostic[paste(diagnostic$model_id, diagnostic$sim_year, sep = "\r") %in%
        paste(complete_expected$model_id, complete_expected$sim_year, sep = "\r"), , drop = FALSE]
      weather <- baseline_hist$sim_summary$weather
      if (is.data.frame(weather) && all(c("name", "units") %in% names(weather))) {
      units <- as.character(weather$units[match(diagnostic$hazard, weather$name)])
      known <- !is.na(units) & nzchar(units)
      continuous <- diagnostic$contrast == "continuous_coefficient_change"
      diagnostic$weather_units[known & continuous] <- units[known & continuous]
    }
    diagnostic$weather_units[diagnostic$contrast != "continuous_coefficient_change"] <-
      "category contrast; no per-unit slope"
      tails <- .policy_metric_tails(annual_full, nm, metadata$adverse_tail,
        baseline_series = bmatrix, required_models = required_models)
      scenario_status <- if (nrow(summary)) "ok" else "unavailable"
      scenario_reason <- if (nrow(summary)) NULL else "No complete finite annual states for expected summary."
      list(status = scenario_status, reason = scenario_reason, annual = complete_expected,
        decile_annual = decile_annual,
        annual_full = annual_full, summary = summary,
        return_period = tails, adverse_support = attr(tails, "adverse_support"),
        adverse_by_model = attr(tails, "adverse_by_model"),
        mechanisms = diagnostic)
    }, error = function(e) {
      bmatrix <- if (!is.null(endpoint_series_baseline[[nm]]$out)) {
        by_model_matrix(endpoint_series_baseline[[nm]]$out)
      } else NULL
      required <- unique(c(names(owners_b[[nm]]$pipelines), if (!is.null(bmatrix)) bmatrix$model_ids))
      tails <- .policy_metric_tails(data.frame(), nm, metadata$adverse_tail,
        baseline_series = bmatrix, required_models = required)
      list(status = "unavailable", reason = conditionMessage(e), annual = data.frame(),
        summary = data.frame(), decile_annual = data.frame(), return_period = tails,
        adverse_support = attr(tails, "adverse_support"),
        adverse_by_model = attr(tails, "adverse_by_model"), mechanisms = data.frame())
    })
    result$scenarios[[nm]] <- calculated
  }
  good <- Filter(function(x) identical(x$status, "ok"), result$scenarios)
  result$annual <- dplyr::bind_rows(lapply(good, `[[`, "annual"))
  result$decile_annual <- dplyr::bind_rows(lapply(good, `[[`, "decile_annual"))
  result$summary <- dplyr::bind_rows(lapply(good, `[[`, "summary"))
  result$return_period <- dplyr::bind_rows(lapply(result$scenarios, `[[`, "return_period"))
  result$adverse_support <- dplyr::bind_rows(lapply(result$scenarios, `[[`, "adverse_support"))
  result$adverse_by_model <- dplyr::bind_rows(lapply(result$scenarios, `[[`, "adverse_by_model"))
  if (nrow(result$adverse_support)) {
    result$adverse_support$required_model_count <- ave(result$adverse_support$model_id,
      result$adverse_support$scenario, FUN = function(x) length(unique(x)))
    result$adverse_support$supported_model_count <- ave(
      as.integer(result$adverse_support$status == "ok"), result$adverse_support$scenario,
      FUN = sum)
  }
  # Tail availability is independent from expected-summary availability.
  mechanism_annual <- dplyr::bind_rows(lapply(good, `[[`, "mechanisms"))
  mechanism_summary <- data.frame()
  if (nrow(mechanism_annual)) {
    numeric_fields <- c("repositioning", "interaction", "positive_repositioning_share",
      "negative_repositioning_share", "positive_interaction_share", "negative_interaction_share", "tau_pre", "tau_post")
    mechanism_summary <- mechanism_annual |>
      dplyr::group_by(.data$scenario, .data$hazard, .data$category, .data$contrast,
        .data$model_units, .data$weather_units, .data$model_id) |>
      dplyr::summarise(dplyr::across(dplyr::all_of(numeric_fields), mean), .groups = "drop") |>
      dplyr::group_by(.data$scenario, .data$hazard, .data$category, .data$contrast,
        .data$model_units, .data$weather_units) |>
      dplyr::summarise(dplyr::across(dplyr::all_of(numeric_fields), mean), n_models = dplyr::n(), .groups = "drop")
  }
  result$mechanisms <- list(annual = mechanism_annual, summary = mechanism_summary,
    fitted_curve = if (prepared$repositioning_modeled) prepared$context$rif_grid else NULL,
    curve_scope = "unchanged Step 1 fitted curve; main-derived pre/post ranks",
    repositioning_status = if (prepared$repositioning_modeled) "modeled" else "Not modeled by this engine",
    interaction_status = if (prepared$interaction_included) "included" else "Interaction not included in fitted model")
  result$mechanisms$metadata <- list(scope = "production_prediction_rows",
    center_method = "equal_model_mean", scale = "model_scale", uncertainty = "central_only",
    model_units = if (isTRUE(so$transform == "log")) "log outcome units" else "model outcome units",
    weather_units = "exact fitted weather-input units; unit label unavailable",
    rank_convention = "fixed main-derived pre/post ranks; interaction evaluated at post-main rank",
    included_terms = "canonical repositioning and weather-policy interaction channel changes only",
    excluded_terms = "not a complete derivative of nonlinear fitted model terms")
  result$metadata$effective_residuals <- if (nrow(result$annual)) unique(result$annual$effective_residuals) else character()
  result$metadata$mixed_effective_residuals <- length(result$metadata$effective_residuals) > 1L
  focus <- result$scenarios[[focus_scenario]]
  result$status <- focus$status %||% "unavailable"
  result$reason <- focus$reason %||% if (is.null(focus)) "Results focus scenario unavailable." else NULL
  result
}

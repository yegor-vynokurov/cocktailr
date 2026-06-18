#' Cocktail clustering (sparse matrix)
#'
#' Fast Cocktail agglomeration for vegetation data supplied either as a
#' **plots × species** table (`input_format = "wide"`) or as a **long**
#' plot–species–value table (`input_format = "long"`).
#'
#' @description
#' This implementation:
#' - Accepts vegetation data in either **wide** or **long** format.
#' - **Binarizes** the input for clustering: values > 0 become 1; values <= 0 or `NA` become 0.
#' - **Drops empty species** (all-zero columns) before clustering (and keeps `vegmatrix` aligned).
#' - For **long** input, aggregates duplicate plot–species rows using `sum()`,
#'   caps aggregated values at 100, and drops empty plots.
#' - Computes the association coefficient (\eqn{\phi}) at each round from one sparse
#'   crossproduct for speed and exactness.
#' - Uses a **fixed, reproducible tie order**: when several pairs share the same
#'   maximum \eqn{\phi} at a step, they are processed in the same order that R fills the
#'   lower-triangular distance matrix (scan by increasing column, then row).
#' - Stores `Plot.cluster` as a sparse `dgCMatrix` (from the **Matrix** package),
#'   containing either binary membership or relative cover per plot and cluster.
#'   If you need a base R matrix, convert manually, e.g.:
#'   `plot_cluster_dense <- as.matrix(res$Plot.cluster)`.
#' - Optionally stores the internally used, cleaned and aligned vegetation matrix
#'   (`vegmatrix`) as a sparse `dgCMatrix` (plots × species), which can be reused
#'   in downstream functions (e.g. `assign_releves()`) without passing the original
#'   vegetation table again.
#' - Optionally writes **relative cover** into `Plot.cluster` instead of binary membership
#'   via `plot_values = "rel_cover"`; relative cover is defined as
#'   (sum of cluster species covers per plot) / (total cover of the plot),
#'   and values are zeroed for plots not meeting the m-threshold (cluster membership).
#' - Optionally computes **species–cluster association coefficients** (`Species.cluster.phi`),
#'   a species × clusters matrix of \eqn{\phi} between species presence and cluster membership,
#'   using sparse crossproducts internally.
#'
#' @param vegmatrix Vegetation data supplied either as:
#'   \itemize{
#'     \item a matrix or data frame with **plots in rows** and **species in columns**
#'           when `input_format = "wide"`; or
#'     \item a data frame in **long format** when `input_format = "long"`,
#'           containing plot IDs, species IDs, and numeric values in the columns
#'           specified by `long`.
#'   }
#'   The data are used twice:
#'   (1) they are **binarized** internally to drive clustering, and
#'   (2) their **original numeric values** (with `NA` treated as 0) are used to compute
#'       relative cover when `plot_values = "rel_cover"`.
#'
#' @param progress Logical; show a text progress bar (default `TRUE`).
#'
#' @param plot_values Character; one of `c("binary", "rel_cover")`.
#'   \itemize{
#'     \item `"binary"` (default): `Plot.cluster` stores 0/1 plot membership per merge.
#'     \item `"rel_cover"`: `Plot.cluster` stores the **relative cover** per plot and merge:
#'           sum of covers over the cluster’s species divided by the total cover of the plot,
#'           but **only** for plots that meet the current merge’s m-threshold (membership);
#'           non-member plots or plots with zero total cover are set to 0.
#'   }
#'
#' @param species_cluster_phi Logical; if `TRUE`, compute and return
#'   `Species.cluster.phi`, a species × clusters matrix of \eqn{\phi} association
#'   coefficients between species presence (from binarized `vegmatrix`) and cluster
#'   membership (from `Plot.cluster > 0`). Set `species_cluster_phi = TRUE` if you plan
#'   to use downstream functions that rely on species–cluster fidelity values,
#'   such as `assign_releves()` with phi-based strategies or
#'   `species_in_clusters(..., species_cluster_phi = TRUE)` (default `TRUE`).
#'
#' @param input_format Character; one of `c("wide", "long")`.
#'   \itemize{
#'     \item `"wide"` (default): `vegmatrix` is interpreted as a plots × species table.
#'     \item `"long"`: `vegmatrix` is interpreted as a long-format data frame with
#'           plot, species, and value columns specified by `long`.
#'   }
#'
#' @param long A named list specifying the column names used when
#'   `input_format = "long"`. Must contain:
#'   \itemize{
#'     \item `plot`   — column with plot/relevé IDs,
#'     \item `species` — column with species names or species IDs,
#'     \item `value`   — column with numeric abundance/cover values.
#'   }
#'   Ignored when `input_format = "wide"`.
#'
#' @param save_vegmatrix Logical; if `TRUE` (default), store the internally used,
#'   cleaned and aligned vegetation matrix as a sparse `dgCMatrix` in the returned
#'   object (`$vegmatrix`). Set to `FALSE` to reduce memory usage for large datasets.
#'
#' @param dataset_path Optional character path to the input dataset on disk.
#'   This does not affect clustering itself, but is stored as provenance in the
#'   returned object and can later be used by downstream reporting helpers.
#'
#' @param dataset_label Optional short human-readable dataset label. Useful when
#'   one dataset is known by a project name rather than a file path.
#'
#' @param dataset_type Optional dataset type such as `"synthetic"` or `"real"`.
#'   If omitted, `cocktail_cluster()` tries to reuse provenance attached to the
#'   input object (for example from `generate_synthetic_vegetation_data()`).
#'
#' @return
#' A list of class `"cocktail"` with:
#' \itemize{
#'   \item `Cluster.species`       — integer matrix (n_merges × n_species): species membership per merge.
#'   \item `Cluster.info`          — integer matrix (n_merges × 2): columns `k` (cluster size) and `m` (threshold).
#'   \item `Plot.cluster`          — `dgCMatrix` (n_plots × n_merges): plot values per merge
#'                                   (0/1 for `"binary"`, relative cover for `"rel_cover"`).
#'   \item `Cluster.merged`        — integer matrix (n_merges × 2): left/right children per merge
#'                                   (negative = original species index; positive = earlier merge index).
#'   \item `Cluster.height`        — numeric vector of length n_merges: \eqn{\phi} at each merge.
#'   \item `Species.cluster.phi`   — (optional) numeric matrix (species × clusters) of \eqn{\phi} association
#'                                   coefficients between each species and each cluster
#'                                   (columns named `"c_<cluster_id>"`), with an attribute
#'                                   `"group_info"` giving cluster sizes. `NULL` if
#'                                   `species_cluster_phi = FALSE`.
#'   \item `vegmatrix`             — (optional) `dgCMatrix` (n_plots × n_species): the internally used,
#'                                   cleaned and aligned vegetation matrix (cover values, with `NA`
#'                                   treated as 0), stored sparsely. Rows correspond to `plots` and
#'                                   columns correspond to `species`. `NULL` if `save_vegmatrix = FALSE`.
#'   \item `species`               — character vector of species names kept after cleaning.
#'   \item `plots`                 — character vector of plot names kept after cleaning.
#'   \item `input_format`          — character scalar, either `"wide"` or `"long"`.
#'   \item `dataset`               — list with optional dataset provenance fields such as
#'                                   `type`, `label`, and `path`.
#' }
#'
#' @details
#' - Binarization and removal of empty species happen internally and only affect the
#'   set of columns that contribute to clustering. All returned components are aligned
#'   to the species that had at least one presence after cleaning.
#' - For `input_format = "long"`, the function expects a data frame with plot,
#'   species, and value columns specified by `long`. Rows with missing plot or
#'   species IDs are removed. Duplicate plot–species combinations are aggregated
#'   using `sum()`, and aggregated values above 100 are capped at 100. Plots with
#'   zero total abundance after parsing are removed before clustering.
#' - If `save_vegmatrix = TRUE`, the returned `vegmatrix` component stores the internally
#'   used vegetation matrix after cleaning/alignment (same rows as `plots`, same columns
#'   as `species`) as a sparse `dgCMatrix`, which can be reused in downstream functions.
#'   Set `save_vegmatrix = FALSE` to reduce memory usage for large datasets.
#' - For `plot_values = "rel_cover"`, relative cover is computed from the **original**
#'   vegetation values (after converting `NA` to 0). For each merge, the function:
#'   (1) identifies the cluster’s species, (2) sums their covers per plot,
#'   (3) divides by the total cover in that plot (sum over all species), and
#'   (4) **zeroes** values for plots that do not meet the m-threshold
#'       (i.e. are not assigned to that merge) or have zero total cover.
#' - Basic checks on the cover scale:
#'   if input values appear **binary** (only 0/1) or contain **non-numeric codes**
#'   (e.g. `+, r, 2a`), the function warns and **falls back to `"binary"`** output.
#'   If values look **ordinal** (e.g. 1..6 / 1..10), the function warns but proceeds
#'   to compute relative cover, noting that percentage cover is recommended.
#' - `Species.cluster.phi` is computed from a 2×2 table for every (species, cluster) pair,
#'   using species presence (from binarized `vegmatrix`) and cluster membership
#'   (from `Plot.cluster > 0`). Sparse crossproducts (`Matrix::crossprod`) are used
#'   to obtain co-occurrence counts efficiently; invalid or zero denominators yield
#'   \eqn{\phi} = 0.
#'
#' @import Matrix
#' @importFrom utils txtProgressBar setTxtProgressBar
#' @export

cocktail_cluster <- function(
    vegmatrix,
    progress = TRUE,
    plot_values = c("binary", "rel_cover"),
    species_cluster_phi = TRUE,
    input_format = c("wide", "long"),
    long = list(plot = "plot", species = "species", value = "value"),
    save_vegmatrix = TRUE,
    dataset_path = NULL,
    dataset_label = NULL,
    dataset_type = NULL
) {
  plot_values <- match.arg(plot_values)
  input_format <- match.arg(input_format)

  ## ---- input checks & setup ----
  if (!is.matrix(vegmatrix) && !is.data.frame(vegmatrix)) {
    stop("vegmatrix must be a matrix or data.frame.")
  }

  .scalar_or_null <- function(x, name) {
    if (is.null(x)) {
      return(NULL)
    }
    if (!is.character(x) || length(x) != 1L || is.na(x) || !nzchar(x)) {
      stop("`", name, "` must be NULL or one non-empty character string.")
    }
    x
  }

  .normalize_optional_path <- function(path) {
    if (is.null(path)) {
      return(NULL)
    }
    normalizePath(path, winslash = "/", mustWork = FALSE)
  }

  .dataset_info_from_input <- function(
      vegmatrix,
      input_format,
      dataset_path,
      dataset_label,
      dataset_type
  ) {
    attr_info <- attr(vegmatrix, "cocktailr_dataset_info", exact = TRUE)
    if (!is.list(attr_info)) {
      attr_info <- list()
    }

    path <- .scalar_or_null(dataset_path, "dataset_path") %||%
      .scalar_or_null(attr_info$path %||% NULL, "attr(vegmatrix, 'cocktailr_dataset_info')$path")
    label <- .scalar_or_null(dataset_label, "dataset_label") %||%
      .scalar_or_null(attr_info$label %||% NULL, "attr(vegmatrix, 'cocktailr_dataset_info')$label")
    type <- .scalar_or_null(dataset_type, "dataset_type") %||%
      .scalar_or_null(attr_info$type %||% NULL, "attr(vegmatrix, 'cocktailr_dataset_info')$type")

    if (is.null(label) && !is.null(path)) {
      label <- tools::file_path_sans_ext(basename(path))
    }

    list(
      type = type,
      label = label,
      path = .normalize_optional_path(path),
      input_format = input_format,
      source = attr_info$source %||% NULL,
      representation = attr_info$representation %||% NULL
    )
  }

  dataset_info <- .dataset_info_from_input(
    vegmatrix = vegmatrix,
    input_format = input_format,
    dataset_path = dataset_path,
    dataset_label = dataset_label,
    dataset_type = dataset_type
  )

  .looks_like_long_input <- function(dat, long) {
    is.data.frame(dat) &&
      all(c(long$plot, long$species, long$value) %in% names(dat))
  }

  .coerce_long_to_matrices <- function(dat, long) {
    if (!is.data.frame(dat)) {
      stop("For input_format = \"long\", vegmatrix must be a data.frame.")
    }

    req <- c(long$plot, long$species, long$value)
    miss <- setdiff(req, names(dat))
    if (length(miss)) {
      stop("Long-format input is missing required columns: ", paste(miss, collapse = ", "))
    }

    d <- dat[, req, drop = FALSE]
    names(d) <- c("plot", "species", "value")

    d <- d[!is.na(d$plot) & !is.na(d$species), , drop = FALSE]
    if (!nrow(d)) stop("No valid rows left after removing NA plot/species IDs.")

    if (!is.numeric(d$value)) {
      val_num <- suppressWarnings(as.numeric(as.character(d$value)))
      bad <- is.na(val_num) & !is.na(d$value)
      if (any(bad)) {
        stop("Long-format value column contains non-numeric values. ",
             "Please recode cover values before using input_format = \"long\".")
      }
      d$value <- val_num
    }
    d$value[is.na(d$value)] <- 0

    plot_levels <- unique(as.character(d$plot))
    spp_levels  <- unique(as.character(d$species))
    d$plot      <- factor(as.character(d$plot), levels = plot_levels)
    d$species   <- factor(as.character(d$species), levels = spp_levels)

    # Detect duplicate plot-species rows before aggregation
    key <- paste0(as.character(d$plot), "\r", as.character(d$species))
    dup_row_count <- sum(duplicated(key))
    if (dup_row_count > 0L) {
      dup_combo_count <- sum(table(key) > 1L)
      warning(
        dup_row_count, " duplicate plot-species row(s) detected in long-format input across ",
        dup_combo_count, " duplicated plot-species combination(s). ",
        "Values were aggregated using sum() and capped at 100. ",
        "If you need different behavior (e.g., max/mean), please modify the input data before calling cocktail_cluster()."
      )
    }

    d_agg <- stats::aggregate(value ~ plot + species, data = d, FUN = base::sum)

    # Cap aggregated cover values at 100 (only affects long-format value aggregation)
    n_cap <- sum(d_agg$value > 100, na.rm = TRUE)
    if (n_cap > 0L) {
      d_agg$value[d_agg$value > 100] <- 100
    }

    M_cover_sparse <- Matrix::sparseMatrix(
      i = as.integer(d_agg$plot),
      j = as.integer(d_agg$species),
      x = d_agg$value,
      dims = c(length(plot_levels), length(spp_levels)),
      dimnames = list(plot_levels, spp_levels)
    )

    # Always drop empty plots; warn how many were removed
    keep_rows <- Matrix::rowSums(M_cover_sparse != 0) > 0
    n_empty <- sum(!keep_rows)
    if (n_empty > 0L) {
      warning(
        n_empty, " empty plot(s) were detected in long-format input and dropped ",
        "(all values were 0 after parsing/aggregation)."
      )
      M_cover_sparse <- M_cover_sparse[keep_rows, , drop = FALSE]
    }

    M_pa_sparse <- Matrix::drop0((M_cover_sparse > 0) * 1L)

    list(
      vm_raw = as.matrix(M_cover_sparse),
      X0     = as(M_pa_sparse, "dgCMatrix"),
      plots  = rownames(M_cover_sparse),
      species = colnames(M_cover_sparse)
    )
  }

  if (identical(input_format, "wide") && .looks_like_long_input(vegmatrix, long)) {
    warning(
      "input_format = \"wide\", but input also matches the specified long-format columns (",
      paste(c(long$plot, long$species, long$value), collapse = ", "),
      "). If this is a long table, use input_format = \"long\"."
    )
  }

  if (identical(input_format, "long")) {
    parsed <- .coerce_long_to_matrices(
      dat = vegmatrix,
      long = long
    )

    vm_raw  <- parsed$vm_raw
    X0      <- parsed$X0
    plots   <- parsed$plots
    species <- parsed$species

  } else {
    # wide format (original behavior)
    vm_raw <- as.matrix(vegmatrix)
    vm_raw[is.na(vm_raw)] <- 0

    vm <- vm_raw
    vm <- (vm > 0) * 1L

    plots   <- rownames(vm); if (is.null(plots))   plots   <- as.character(seq_len(nrow(vm)))
    species <- colnames(vm); if (is.null(species)) species <- as.character(seq_len(ncol(vm)))

    # Drop empty species columns (and align vm_raw)
    keep <- colSums(vm) > 0L
    if (!all(keep)) {
      vm      <- vm[, keep, drop = FALSE]
      vm_raw  <- vm_raw[, keep, drop = FALSE]
      species <- species[keep]
    }

    X0 <- Matrix::Matrix(vm, sparse = TRUE)  # dgCMatrix (0/1)
    rm(vm)
  }

  # Keep original covers for relative cover output and species-cluster phi
  # (vm_raw is now defined for both wide and long input)

  # Detect cover scale for warnings/forcing behavior
  detect_cover_scale <- function(M) {
    vals <- unique(as.vector(M)); vals <- vals[!is.na(vals)]
    if (!length(vals)) return(list(type="unknown", note=NULL))
    num_try <- suppressWarnings(as.numeric(vals))
    non_num <- is.na(num_try)
    if (any(non_num)) return(list(type="non_numeric", note="Non-numeric cover codes detected (e.g., '+', 'r', '2a')."))
    u <- sort(unique(num_try))
    if (all(u %in% c(0,1))) return(list(type="binary", note="Cover data appear to be binary (0/1)."))
    all_int <- all(abs(u - round(u)) < .Machine$double.eps^0.5)
    if (all_int && length(u) <= 10) return(list(type="ordinal", note="Cover data appear ordinal (small integer scale)."))
    list(type="numeric", note=NULL)
  }
  scale_info <- detect_cover_scale(vm_raw)

  # If user asked for relative cover but data unsuitable, warn and force binary
  if (plot_values != "binary") {
    if (scale_info$type %in% c("binary","non_numeric")) {
      warning(sprintf(
        "%s Using binary Plot.cluster instead.",
        if (scale_info$type == "binary") {
          "Cover data are binary (0/1); relative covers are not meaningful."
        } else {
          "Non-numeric cover codes detected; relative covers not computed."
        }
      ))
      plot_values <- "binary"
    } else if (scale_info$type == "ordinal") {
      warning("Cover data look ordinal (e.g., 1..6 / 1..10). Proceeding with relative cover, but percentage cover is recommended.")
    }
  }

  # Ensure alignment between cover matrix and sparse presence/absence matrix
  if (!identical(dim(vm_raw), dim(X0))) {
    stop("Internal error: vm_raw and X0 dimensions are not aligned.")
  }
  if (!identical(rownames(vm_raw), rownames(X0))) {
    stop("Internal error: row names of vm_raw and X0 are not aligned.")
  }
  if (!identical(colnames(vm_raw), colnames(X0))) {
    stop("Internal error: column names of vm_raw and X0 are not aligned.")
  }

  N <- nrow(X0); n <- ncol(X0)
  if (n < 2L) stop("After dropping empty species, need at least 2 species (columns).")
  if (N < 1L) stop("Need at least 1 plot (row).")

  # global frequencies for Expected.plot.freq (from original species)
  p.freq <- as.numeric(Matrix::colSums(X0)) / N
  q.freq <- 1 - p.freq

  # Total cover per plot (denominator for relative cover)
  plot_totals <- rowSums(vm_raw, na.rm = TRUE)

  ## ---- helpers -------------------------------------------------------------
  Expected.plot.freq_ <- function(species.in.cluster) {
    K <- length(species.in.cluster)
    Exp <- array(0, K + 1L)
    Exp_inter <- array(0, K + 1L)
    Exp_inter[1L] <- 1
    for (j in 1L:K) {
      s <- species.in.cluster[j]
      Exp[1L] <- Exp_inter[1L] * q.freq[s]
      if (j > 1L) {
        for (k in 1L:(j - 1L)) {
          Exp[k + 1L] <- Exp_inter[k]     * p.freq[s] +
            Exp_inter[k + 1L] * q.freq[s]
        }
      }
      Exp[j + 1L] <- Exp_inter[j] * p.freq[s]
      for (k in 1L:(j + 1L)) Exp_inter[k] <- Exp[k]
    }
    Exp
  }

  Compare.obs.exp.freq_ <- function(Obs.freq, Exp.freq) {
    Obs <- if (is.matrix(Obs.freq)) as.vector(Obs.freq[, 1L]) else as.vector(Obs.freq)
    K   <- length(Obs) - 1L
    Cum.obs <- array(0, K + 1L)
    Cum.exp <- array(0, K + 1L)
    Cum.obs[K + 1L] <- Obs[K + 1L]
    Cum.exp[K + 1L] <- Exp.freq[K + 1L]
    m <- 1L
    m.found <- -1L
    if (Cum.obs[K + 1L] > Cum.exp[K + 1L]) { m <- K; m.found <- 0L }
    for (j in K:1L) {
      Cum.obs[j] <- Cum.obs[j + 1L] + Obs[j]
      if (m.found == -1L && Cum.obs[j] > 0) m.found <- 0L
      Cum.exp[j] <- Cum.exp[j + 1L] + Exp.freq[j]
      if (j > 1L && m.found == 0L && Cum.exp[j] > Cum.obs[j]) { m <- j; m.found <- 1L }
    }
    m
  }

  .lower_tri_index_vec <- function(i, j, m) {
    x <- i - 1L
    (x * m) - (x * (x + 1L)) / 2 + (j - i)
  }

  # phi via one sparse crossproduct
  phi_max_pairs_crossprod_distorder_ <- function(X) {
    stopifnot(inherits(X, "dgCMatrix"))
    m <- ncol(X)
    if (m < 2L) return(list(max_phi = 0, pairs = matrix(integer(0), ncol = 2)))

    Nn <- nrow(X)
    p  <- as.numeric(Matrix::colSums(X))  # counts

    A <- Matrix::crossprod(X)             # dsCMatrix symmetric, upper triangle stored
    Matrix::diag(A) <- 0L
    if (length(A@x) == 0L) {
      # no co-occurrences → need fallback to include a==0 pairs
      return(list(max_phi = -Inf, pairs = matrix(integer(0), ncol = 2)))
    }

    # indices aligned with A@x (upper triangle, compressed-by-column storage)
    j_idx <- rep.int(seq_len(m), diff(A@p))  # column index per nonzero
    i_idx <- A@i + 1L                        # row index per nonzero (i < j)
    a     <- A@x                             # co-occurrence counts

    b <- p[i_idx] - a
    c <- p[j_idx] - a
    d <- Nn - a - b - c

    den <- sqrt((a + c) * (b + d) * (a + b) * (c + d))
    phi <- ifelse(den > 0, (a * d - b * c) / den, 0)
    phi[!is.finite(phi)] <- 0

    max_phi <- max(phi)
    keep <- which(phi == max_phi)
    if (!length(keep)) return(list(max_phi = -Inf, pairs = matrix(integer(0), ncol = 2)))

    # sort ties by the original lower-triangle linear index (exact which()-order)
    idx <- .lower_tri_index_vec(i_idx[keep], j_idx[keep], m)
    ord <- order(idx)
    pairs <- cbind(e1 = i_idx[keep][ord], e2 = j_idx[keep][ord])
    list(max_phi = max_phi, pairs = pairs)
  }

  # Fallback φ over all pairs, ties sorted by the same lower-triangle index
  phi_max_pairs_fallback_distorder_ <- function(X) {
    stopifnot(inherits(X, "dgCMatrix"))
    m <- ncol(X)
    if (m < 2L) return(list(max_phi = 0, pairs = matrix(integer(0), ncol = 2)))

    Nn <- nrow(X)
    p  <- as.numeric(Matrix::colSums(X))

    best <- -Inf
    out_i <- integer(0)
    out_j <- integer(0)

    for (j in 2L:m) {
      a <- as.numeric(Matrix::t(X[, 1L:(j - 1L), drop = FALSE]) %*% X[, j, drop = FALSE])
      b <- p[1L:(j - 1L)] - a
      c <- p[j]           - a
      d <- Nn - a - b - c
      den <- sqrt((a + c) * (b + d) * (a + b) * (c + d))
      phi <- ifelse(den > 0, (a * d - b * c) / den, 0)
      phi[!is.finite(phi)] <- 0

      cur <- max(phi)
      if (cur > best) {
        keep <- which(phi == cur)
        best <- cur
        out_i <- keep
        out_j <- rep.int(j, length(keep))
      } else if (cur == best) {
        keep <- which(phi == best)
        if (length(keep)) {
          out_i <- c(out_i, keep)
          out_j <- c(out_j, rep.int(j, length(keep)))
        }
      }
    }

    if (!length(out_i)) {
      return(list(max_phi = ifelse(is.finite(best), best, 0),
                  pairs   = matrix(integer(0), ncol = 2)))
    }
    idx <- .lower_tri_index_vec(out_i, out_j, m)
    ord <- order(idx)
    pairs <- cbind(e1 = out_i[ord], e2 = out_j[ord])
    list(max_phi = ifelse(is.finite(best), best, 0), pairs = pairs)
  }

  ## ---- outputs ----
  Cluster.species <- matrix(0L, n - 1L, n, dimnames = list(NULL, species))
  Cluster.info    <- matrix(0L, n - 1L, 2L,
                            dimnames = list(as.character(seq_len(n - 1L)), c("k","m")))
  # Work internally with a *dense* numeric matrix, convert to sparse at the end
  Plot.cluster_dense <- matrix(
    0, nrow = N, ncol = n - 1L,
    dimnames = list(plots, NULL)
  )
  Cluster.merged  <- matrix(0L, n - 1L, 2L)
  Cluster.height  <- array(0, n - 1L)

  ## ---- working state ----
  X         <- X0
  col_names <- colnames(X0); if (is.null(col_names)) col_names <- species
  i <- 0L
  name_last_cluster <- NULL

  pb <- if (isTRUE(progress)) utils::txtProgressBar(min = 0, max = n - 1L, style = 3) else NULL
  on.exit({ if (!is.null(pb)) close(pb) }, add = TRUE)

  ## ---- agglomeration loop ----
  while (i <= (n - 2L)) {

    # fast φ; if needed, fallback (ensures a==0 pairs included when max ≤ 0)
    maxres <- phi_max_pairs_crossprod_distorder_(X)
    if (nrow(maxres$pairs) == 0L || !(is.finite(maxres$max_phi) && maxres$max_phi > 0)) {
      maxres <- phi_max_pairs_fallback_distorder_(X)
      if (nrow(maxres$pairs) == 0L) break
    }

    e1 <- maxres$pairs[, 1L]
    e2 <- maxres$pairs[, 2L]
    multiple.max <- length(e1)

    # circularity filter
    compare1 <- as.vector(t(cbind(e1, e2)))
    if (anyDuplicated(compare1) > 2L) {
      keep <- rep(TRUE, multiple.max)
      for (jj in 2L:multiple.max) {
        compare2 <- compare1[1L:(2L * (jj - 1L))]
        k1 <- sum(!is.na(match(compare2, e1[jj])))
        k2 <- sum(!is.na(match(compare2, e2[jj])))
        if (k1 > 0L & k2 > 0L) keep[jj] <- FALSE
      }
      e1 <- e1[keep]; e2 <- e2[keep]
      multiple.max <- length(e1)
      if (multiple.max == 0L) next
    }

    # respect the (n-1) bound
    remaining_merges <- (n - 1L) - i
    if (remaining_merges <= 0L) break
    if (multiple.max > remaining_merges) {
      e1 <- e1[seq_len(remaining_merges)]
      e2 <- e2[seq_len(remaining_merges)]
      multiple.max <- remaining_merges
    }

    i1 <- i + 1L

    # ----- rename only within current endpoints, and evolve within round -----
    end_idx   <- c(e1, e2)
    end_names <- col_names[end_idx]

    for (jj in seq_len(multiple.max)) {
      if (i >= (n - 1L)) break
      i <- i + 1L
      Cluster.height[i] <- maxres$max_phi

      pos_left  <- match(e1[jj], end_idx)
      pos_right <- match(e2[jj], end_idx)

      left_name  <- end_names[pos_left]
      right_name <- end_names[pos_right]

      if (startsWith(left_name, "c_")) {
        cl1 <- as.integer(sub("c_", "", left_name))
        Cluster.merged[i, 1L] <- cl1
        Cluster.species[i, Cluster.species[cl1, ] == 1L] <- 1L
      } else {
        f1 <- match(left_name, species)
        Cluster.merged[i, 1L] <- -f1
        Cluster.species[i, f1] <- 1L
      }

      if (startsWith(right_name, "c_")) {
        cl2 <- as.integer(sub("c_", "", right_name))
        Cluster.merged[i, 2L] <- cl2
        Cluster.species[i, Cluster.species[cl2, ] == 1L] <- 1L
      } else {
        f2 <- match(right_name, species)
        Cluster.merged[i, 2L] <- -f2
        Cluster.species[i, f2] <- 1L
      }

      # evolve endpoint names inside the current batch
      newc <- paste0("c_", i)
      tmp <- end_names
      tmp[tmp == left_name]  <- newc
      tmp[tmp == right_name] <- newc
      end_names <- tmp

      # k, m, plot assignment (computed from original X0)
      k <- sum(Cluster.species[i, ])
      Cluster.info[i, 1L] <- k

      spp_idx <- which(Cluster.species[i, ] > 0L)
      species_in_plot <- as.integer(Matrix::rowSums(X0[, spp_idx, drop = FALSE]))
      Obs_plot_freq <- tabulate(species_in_plot + 1L, nbins = k + 1L)
      Exp_plot_freq <- Expected.plot.freq_(spp_idx) * N
      Cluster.info[i, 2L] <- Compare.obs.exp.freq_(Obs_plot_freq, Exp_plot_freq)

      # Fill Plot.cluster per option (dense matrix)
      if (plot_values == "binary") {
        # 0/1 membership
        Plot.cluster_dense[species_in_plot >= Cluster.info[i, 2L], i] <- 1

      } else if (plot_values == "rel_cover") {
        # Relative cover: sum of cluster covers / total cover per plot,
        # zeroed outside membership or when total cover is zero
        cov_block <- vm_raw[, spp_idx, drop = FALSE]
        sums <- rowSums(cov_block, na.rm = TRUE)
        rel <- ifelse(plot_totals > 0, sums / plot_totals, 0)
        rel[species_in_plot < Cluster.info[i, 2L]] <- 0
        Plot.cluster_dense[, i] <- rel
      }
    }

    col_names[end_idx] <- end_names

    n2 <- ncol(X)
    if (n2 == 3L) {
      name_last_cluster <- col_names[-c(e1[1], e2[1])]
    }

    idx_e1_unique <- !duplicated(col_names[e1], fromLast = TRUE)
    idx_e2_unique <- !duplicated(col_names[e2], fromLast = TRUE)
    index.e <- seq.int(i1, i)[idx_e1_unique & idx_e2_unique]

    drop_cols <- sort(unique(c(e1, e2)))
    if (length(index.e)) {
      newcols <- do.call(cbind, lapply(index.e, function(kid) {
        Matrix::Matrix(Plot.cluster_dense[, kid] > 0, sparse = TRUE)
      }))
      colnames(newcols) <- paste0("c_", index.e)
      X <- cbind(X[, -drop_cols, drop = FALSE], newcols)
      col_names <- c(col_names[-drop_cols], colnames(newcols))
    } else {
      X <- X[, -drop_cols, drop = FALSE]
      col_names <- col_names[-drop_cols]
    }

    if (ncol(X) == 2L && length(name_last_cluster) == 1L) {
      col_names[1L] <- name_last_cluster
    }

    # φ = 0 tail: once every plot is in the current cluster, finish remaining merges at height 0
    if (sum(Plot.cluster_dense[, i] > 0) == N) {
      remaining <- (n - 1L) - i
      if (remaining > 0L) {
        for (j in (i + seq_len(remaining))) {
          # sanity: j within 1..n-1
          stopifnot(j >= 1L, j <= nrow(Cluster.merged))

          g1  <- ncol(X)
          cl1 <- as.integer(sub("c_", "", col_names[g1]))
          Cluster.merged[j, 1L] <- cl1

          g2  <- 1L
          cl2 <- as.integer(sub("c_", "", col_names[g2]))
          Cluster.merged[j, 2L] <- cl2

          Cluster.height[j] <- 0
          Cluster.info[j, 1L] <- sum(Cluster.species[j, ])
          Cluster.info[j, 2L] <- 1L

          Cluster.species[j, Cluster.species[cl1, ] == 1L] <- 1L
          Cluster.species[j, Cluster.species[cl2, ] == 1L] <- 1L

          # Tail: write Plot.cluster_dense
          if (plot_values == "binary") {

            Plot.cluster_dense[, j] <- 1

          } else if (plot_values == "rel_cover") {

            spp_idx <- which(Cluster.species[j, ] > 0L)
            cov_block <- vm_raw[, spp_idx, drop = FALSE]
            sums <- if (length(spp_idx)) rowSums(cov_block, na.rm = TRUE) else rep(0, N)
            species_in_plot_tail <- as.integer(Matrix::rowSums(X0[, spp_idx, drop = FALSE]))
            rel <- ifelse(plot_totals > 0, sums / plot_totals, 0)
            rel[species_in_plot_tail < 1L] <- 0
            Plot.cluster_dense[, j] <- rel
          }

          X <- cbind(X, Matrix::Matrix(Plot.cluster_dense[, j] > 0, sparse = TRUE))
          colnames(X)[ncol(X)] <- paste0("c_", j)
          X <- X[, -c(g1, g2), drop = FALSE]
          col_names <- c(col_names, paste0("c_", j))
          col_names <- col_names[-c(g1, g2)]
        }
        # advance i by exactly how many merges we just filled
        i <- i + remaining
      }
    }

    if (!is.null(pb)) utils::setTxtProgressBar(pb, min(i, n - 1L))
    if (i >= (n - 1L)) break
  }

  ## ---- convert dense Plot.cluster to sparse dgCMatrix ----
  Plot.cluster <- Matrix::Matrix(Plot.cluster_dense, sparse = TRUE)

  ## ---- species × node phi matrix (optional species–cluster associations) ----
  Species.cluster.phi <- NULL
  if (isTRUE(species_cluster_phi)) {
    n_nodes <- nrow(Cluster.species)

    # species presence (plots × species, 0/1) as numeric sparse (dgCMatrix)
    X_f <- Matrix::Matrix((vm_raw > 0) * 1, sparse = TRUE)
    # node membership (plots × nodes, 0/1) as numeric sparse (dgCMatrix)
    G_f <- Matrix::Matrix((Plot.cluster > 0) * 1, sparse = TRUE)

    if (nrow(X_f) != nrow(G_f) || ncol(G_f) != n_nodes) {
      stop("Internal mismatch computing Species.cluster.phi: dimensions do not align.")
    }

    # co-occurrences via sparse crossprod
    a_sc <- Matrix::crossprod(X_f, G_f)   # nsp × n_nodes (Matrix)
    a_sc <- as.matrix(a_sc)               # dense numeric for phi algebra

    # margins (sparse-aware)
    p_sc  <- Matrix::colSums(X_f)         # species totals
    g1_sc <- Matrix::colSums(G_f)         # node sizes

    nsp    <- length(p_sc)
    Nf     <- nrow(X_f)
    n_nodes_check <- length(g1_sc)
    stopifnot(nsp == nrow(a_sc), n_nodes_check == ncol(a_sc))

    # broadcasted
    b_sc <- matrix(p_sc,  nrow = nsp, ncol = n_nodes_check) - a_sc
    c_sc <- matrix(g1_sc, nrow = nsp, ncol = n_nodes_check, byrow = TRUE) - a_sc
    d_sc <- (Nf - matrix(g1_sc, nrow = nsp, ncol = n_nodes_check, byrow = TRUE)) - b_sc

    den_sc <- sqrt((a_sc + c_sc) * (b_sc + d_sc) * (a_sc + b_sc) * (c_sc + d_sc))
    phi_sc <- (a_sc * d_sc - b_sc * c_sc) / den_sc
    phi_sc[!is.finite(den_sc) | den_sc <= 0] <- 0

    colnames(phi_sc) <- paste0("c_", seq_len(n_nodes_check))
    rownames(phi_sc) <- species

    GI <- data.frame(
      col        = colnames(phi_sc),
      cluster_id = seq_len(n_nodes_check),
      n_plots    = as.numeric(g1_sc),
      stringsAsFactors = FALSE
    )
    attr(phi_sc, "group_info") <- GI

    Species.cluster.phi <- phi_sc
  }


  ## ---- optionally store aligned vegetation matrix (cover values) as sparse dgCMatrix ----
  vegmatrix_out <- NULL
  if (isTRUE(save_vegmatrix)) {
    vegmatrix_out <- as(Matrix::Matrix(vm_raw, sparse = TRUE), "dgCMatrix")
  }

  ## ---- result ----
  res <- list(
    Cluster.species      = Cluster.species,
    Cluster.info         = Cluster.info,
    Plot.cluster         = Plot.cluster,
    Cluster.merged       = Cluster.merged,
    Cluster.height       = Cluster.height,
    Species.cluster.phi  = Species.cluster.phi,
    species              = species,
    plots                = plots,
    vegmatrix            = vegmatrix_out,
    input_format         = input_format,
    dataset              = dataset_info
  )
  class(res) <- c("cocktail", class(res))
  res
}

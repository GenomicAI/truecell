"""Differential expression / marker gene detection.

Mirrors Seurat's FindMarkers() and FindAllMarkers().
"""
from __future__ import annotations

import warnings
from typing import Optional, Union

import numpy as np
import pandas as pd
import scipy.sparse as sp
from scipy.stats import mannwhitneyu

from .lazy import is_lazy

# Seurat's `pseudocount.use`, added to each group's *summed* un-logged expression
# before dividing by the group size. See the fold-change block in `find_markers`.
PSEUDOCOUNT = 1.0


def _row_pct_positive(m) -> np.ndarray:
    """Fraction of columns in which each row is positive."""
    if sp.issparse(m):
        return np.asarray((m > 0).sum(axis=1)).ravel() / m.shape[1]
    return (m > 0).mean(axis=1)


def expm1_keeping_sparsity(m):
    """``expm1(m)``, without densifying a sparse ``m``.

    ``expm1(0) == 0``, so the transform leaves the sparsity pattern untouched
    and applies to the stored values alone. That is what lets the fold-change
    pre-filter run on the sparse matrix instead of a dense copy of it.

    Shared with :func:`truecell.aggregate.average_expression`, which un-does the
    same log1p normalization before averaging. The two must agree — Seurat's
    fold change and its ``AverageExpression`` are the same back-transform — and a
    second copy of these three lines is exactly the kind of divergence nothing
    downstream could detect.
    """
    if sp.issparse(m):
        transformed = m.copy()
        transformed.data = np.expm1(transformed.data)
        return transformed
    return np.expm1(m)


def _row_expm1_sum(m) -> np.ndarray:
    """Row sums of ``expm1(m)``, without densifying a sparse ``m``."""
    transformed = expm1_keeping_sparsity(m)
    if sp.issparse(transformed):
        return np.asarray(transformed.sum(axis=1)).ravel()
    return transformed.sum(axis=1)


def _dense_rows(m, rows: np.ndarray) -> np.ndarray:
    """The given rows of ``m`` as a dense float array.

    The per-gene tests below need dense vectors, and this is the only place they
    get one. It runs *after* both pre-filters, so the array is (tested genes ×
    cells) rather than (all genes × cells) — on PBMC 3k that is ~1.6k rows of
    13.7k, and the difference is most of what `find_markers` used to cost.
    """
    if sp.issparse(m):
        return m.tocsr()[rows, :].toarray().astype(float, copy=False)
    return np.asarray(m)[rows, :].astype(float, copy=False)


def _ident_sort_key(label: str):
    """Sort cluster labels numerically when they are all numeric.

    Seurat's identities are a factor whose levels for `FindClusters` output are
    0, 1, ... in numeric order. Plain string sorting puts "10" before "2", so a
    dataset with eleven or more clusters would come back in a different cluster
    order from Seurat's — silently, and only past ten clusters.
    """
    text = str(label)
    return (0, int(text), "") if text.lstrip("-").isdigit() else (1, 0, text)


def _roc_auc(x1: np.ndarray, x2: np.ndarray) -> tuple[float, float]:
    """Return (AUC, power) for classifying group 1 vs group 2 by expression.

    AUC is the Mann-Whitney U statistic normalised to [0, 1]; power = |2·AUC−1|
    (Seurat's classification power), 0 = random, 1 = perfect separation.
    """
    n1, n2 = len(x1), len(x2)
    if n1 == 0 or n2 == 0:
        return 0.5, 0.0
    try:
        u, _ = mannwhitneyu(x1, x2, alternative="two-sided", method="asymptotic")
        auc = u / (n1 * n2)
    except ValueError:
        auc = 0.5
    return float(auc), float(abs(2.0 * auc - 1.0))


def _lr_pvalue(expr: np.ndarray, group: np.ndarray, latent: Optional[np.ndarray]) -> float:
    """Logistic-regression likelihood-ratio test (Seurat's 'LR').

    Fits group ~ expr (+ latent) vs the reduced group ~ (latent); the LRT on the
    dropped expression term is χ²(df=1).
    """
    import statsmodels.api as sm
    from scipy.stats import chi2

    n = len(group)
    full_cols = [np.ones(n), expr]
    red_cols = [np.ones(n)]
    if latent is not None and latent.size:
        full_cols.append(latent)
        red_cols.append(latent)
    X_full = np.column_stack(full_cols)
    X_red = np.column_stack(red_cols)
    try:
        with warnings.catch_warnings():
            # Marker genes often (near-)perfectly separate the groups; that is
            # the signal, not an error — silence statsmodels' separation noise.
            warnings.simplefilter("ignore")
            full = sm.GLM(group, X_full, family=sm.families.Binomial()).fit()
            red = sm.GLM(group, X_red, family=sm.families.Binomial()).fit()
        stat = red.deviance - full.deviance
        return float(chi2.sf(max(stat, 0.0), df=1))
    except Exception:
        return 1.0


def _negbinom_pvalue(counts: np.ndarray, group: np.ndarray, latent: Optional[np.ndarray]) -> float:
    """Negative-binomial GLM Wald test on counts (Seurat's 'negbinom').

    Seurat's ``GLMDETest`` fits ``MASS::glm.nb`` — which estimates the dispersion
    by **maximum likelihood** — and reads the **Wald** p-value off the group
    coefficient (``summary(...)$coef[2, 4]``). ``statsmodels``'
    ``NegativeBinomial`` does the same job: it profiles out alpha by ML rather
    than taking it as given.

    This replaced a fixed method-of-moments dispersion plus a likelihood-ratio
    test, which is a different estimator *and* a different statistic. On pbmc3k
    it read HLA-DRA at 5.5e-128 against R's 1.1e-321 — the ordering of the top
    genes largely survived (Spearman 0.94 on expressed genes), but the values did
    not, and anyone thresholding on p or comparing against an R run saw numbers
    that were wrong by ~190 orders of magnitude.
    """
    import statsmodels.api as sm

    y = counts.astype(float)
    if y.mean() <= 0:
        return 1.0

    n = len(y)
    cols = [np.ones(n), group]
    if latent is not None and latent.size:
        cols.append(latent)
    X = np.column_stack(cols)
    try:
        with warnings.catch_warnings():
            warnings.simplefilter("ignore")
            fit = sm.NegativeBinomial(y, X).fit(disp=0, maxiter=200)
        p = float(fit.pvalues[1])
    except Exception:
        return 1.0
    # glm.nb can fail to converge on near-empty genes; R drops those rows, and a
    # non-finite p here means the same thing — no evidence, not strong evidence.
    return 1.0 if not np.isfinite(p) else p


def _poisson_pvalue(counts: np.ndarray, group: np.ndarray, latent: Optional[np.ndarray]) -> float:
    """Poisson GLM Wald test on counts (Seurat's 'poisson').

    The other half of Seurat's ``GLMDETest``: where ``negbinom`` fits
    ``MASS::glm.nb``, this fits ``glm(family = "poisson")`` and reads the same
    **Wald** p-value off the group coefficient (``summary(...)$coef[2, 4]``).
    Both run on the **counts** layer, not the normalized one.

    The p-value is normal-based rather than t-based, on both sides: a Poisson
    GLM holds its dispersion fixed at 1, so R's ``summary.glm`` reports a z
    value, and ``statsmodels``' ``GLM`` likewise leaves ``use_t`` off when the
    family's scale is fixed.

    **This test is anti-conservative on scRNA-seq, by construction.** Fixing the
    dispersion at 1 asserts ``Var = mean``, and UMI counts are overdispersed, so
    the standard errors come out too small and the p-values too extreme —
    routinely by tens of orders of magnitude against ``negbinom`` on the same
    gene. That is a property of the model Seurat exposes, not of this port;
    ``negbinom`` estimates the dispersion instead and is the better-calibrated
    of the two. It is offered because Seurat offers it, and it is fast.
    """
    import statsmodels.api as sm

    y = counts.astype(float)
    if y.mean() <= 0:
        return 1.0

    n = len(y)
    cols = [np.ones(n), group]
    if latent is not None and latent.size:
        cols.append(latent)
    X = np.column_stack(cols)
    try:
        with warnings.catch_warnings():
            warnings.simplefilter("ignore")
            fit = sm.GLM(y, X, family=sm.families.Poisson()).fit()
        p = float(fit.pvalues[1])
    except Exception:
        return 1.0
    # A gene with no variance leaves the group coefficient exactly 0 (p = 1
    # already); one that fails to converge gives a non-finite p. Both mean "no
    # evidence" — see the divergence note in `find_markers`' docstring.
    return 1.0 if not np.isfinite(p) else p


def _mast_pvalue(expr: np.ndarray, group: np.ndarray, latent: Optional[np.ndarray]) -> float:
    """MAST two-part hurdle likelihood-ratio test (Finak 2015; Seurat's 'MAST').

    Fits a *discrete* logistic model of detection (``expr > 0``) and a
    *continuous* Gaussian model of the log-expression among detected cells, each
    as ``~ group (+ latent)``. Because the hurdle likelihood factorises into its
    detection and magnitude parts, the combined LR statistic is the sum of the
    two components' statistics tested on the sum of their degrees of freedom.
    Components that carry no information (constant detection, or magnitude seen in
    only one group) contribute 0 df and are dropped.
    """
    import statsmodels.api as sm
    from scipy.stats import chi2

    n = len(expr)
    detect = (expr > 0).astype(float)

    def _design(mask: np.ndarray, include_group: bool) -> np.ndarray:
        cols = [np.ones(int(mask.sum()))]
        if include_group:
            cols.append(group[mask])
        if latent is not None and latent.size:
            cols.append(latent[mask])
        return np.column_stack(cols)

    stat = 0.0
    df = 0

    # ---- discrete component: logistic LRT on the group term ------------------
    if 0.0 < detect.sum() < n:  # detection varies → group term is estimable
        allmask = np.ones(n, dtype=bool)
        try:
            with warnings.catch_warnings():
                warnings.simplefilter("ignore")
                full = sm.GLM(detect, _design(allmask, True),
                              family=sm.families.Binomial()).fit()
                red = sm.GLM(detect, _design(allmask, False),
                             family=sm.families.Binomial()).fit()
            d = red.deviance - full.deviance
            if np.isfinite(d) and d > 0:
                stat += d
                df += 1
        except Exception:
            pass

    # ---- continuous component: Gaussian LRT among detected cells -------------
    pos = expr > 0
    if pos.sum() >= 3 and np.unique(group[pos]).size > 1 and np.ptp(expr[pos]) > 0:
        try:
            with warnings.catch_warnings():
                warnings.simplefilter("ignore")
                full = sm.OLS(expr[pos], _design(pos, True)).fit()
                red = sm.OLS(expr[pos], _design(pos, False)).fit()
            d = 2.0 * (full.llf - red.llf)
            if np.isfinite(d) and d > 0:
                stat += d
                df += 1
        except Exception:
            pass

    if df == 0:
        return 1.0
    return float(chi2.sf(stat, df=df))


def _bimod_likelihood(x: np.ndarray, xmin: float = 0.0) -> float:
    """Log-likelihood of ``x`` under the McDavid 2013 bimodal model.

    A point mass at/below ``xmin`` (the un-detected fraction, ``1 - α``) plus a
    Gaussian on the detected values. Mirrors Seurat's ``bimodLikData``.
    """
    from scipy.stats import norm

    n = len(x)
    if n == 0:
        return 0.0
    x_pos = x[x > xmin]
    n_pos = len(x_pos)
    n_zero = n - n_pos
    alpha = min(max(n_pos / n, 1e-5), 1 - 1e-5)  # detection rate, clamped
    lik_a = n_zero * np.log(1 - alpha)
    if n_pos == 0:
        return float(lik_a)
    sd = np.std(x_pos, ddof=1) if n_pos >= 2 else 1.0
    if sd == 0:
        sd = 1.0  # degenerate all-equal detected values (Seurat guards n<2 only)
    lik_b = n_pos * np.log(alpha) + float(np.sum(norm.logpdf(x_pos, loc=x_pos.mean(), scale=sd)))
    return float(lik_a + lik_b)


def _bimod_pvalue(x1: np.ndarray, x2: np.ndarray, xmin: float = 0.0) -> float:
    """McDavid 2013 bimodal likelihood-ratio test (Seurat's 'bimod').

    ``2·(logLik(x1) + logLik(x2) − logLik(x1∪x2))`` under the bimodal model is
    χ² with 3 df (the (α, μ, σ) triple that the pooled model constrains).
    """
    from scipy.stats import chi2

    lrt = 2.0 * (
        _bimod_likelihood(x1, xmin)
        + _bimod_likelihood(x2, xmin)
        - _bimod_likelihood(np.concatenate([x1, x2]), xmin)
    )
    return float(chi2.sf(max(lrt, 0.0), df=3))


def find_markers(
    seurat,
    ident_1: Union[str, list[str]],
    ident_2: Optional[Union[str, list[str]]] = None,
    assay: Optional[str] = None,
    layer: Optional[str] = None,
    test_use: str = "wilcox",
    only_pos: bool = False,
    min_pct: float = 0.1,
    logfc_threshold: float = 0.25,
    features: Optional[list[str]] = None,
    latent_vars: Optional[list[str]] = None,
    sample_col: Optional[str] = None,
    max_cells_per_ident: Optional[int] = None,
    random_seed: int = 1,
) -> pd.DataFrame:
    """Find differentially expressed marker genes.

    Mirrors R's FindMarkers(pbmc, ident.1 = 2).

    Parameters
    ----------
    ident_1         : cluster label(s) for group 1
    ident_2         : cluster label(s) for group 2 (None = all others)
    test_use        : statistical test — 'wilcox' (default), 't', 'bimod'
                      (McDavid 2013 bimodal LRT), 'LR' (logistic-regression LRT),
                      'negbinom' (negative-binomial GLM Wald test on counts),
                      'poisson' (Poisson GLM Wald test on counts — fast, but
                      anti-conservative on overdispersed UMI data; prefer
                      'negbinom'), 'mast' (MAST two-part hurdle LRT on
                      log-normalized data), 'deseq2' (pseudobulk DESeq2 — sums
                      counts per sample then tests sample-level, requires
                      ``sample_col``; needs ``pip install truecell[deseq2]``),
                      or 'roc' (AUC classifier power).
    only_pos        : only return positive markers
    min_pct         : minimum fraction cells expressing gene in either group
    logfc_threshold : minimum log2 fold-change filter
    features        : restrict to these genes (default: all)
    latent_vars     : metadata columns to regress out as covariates in the
                      'LR', 'negbinom', 'poisson' and 'mast' models — the same
                      four Seurat's ``DEmethods_latent()`` names for its
                      ``latent.vars``.
                      Note that Seurat's ``MASTDETest`` fits ``~ condition``
                      alone — it adds **no** cellular detection rate term unless
                      you pass one — so leaving this empty is what matches
                      Seurat's default. Passing CDR is the MAST paper's advice,
                      and a deliberate departure from Seurat.
    sample_col      : metadata column identifying pseudobulk replicates (donor /
                      sample); required for ``test_use='deseq2'``, ignored
                      otherwise.
    max_cells_per_ident : downsample each group to this many cells

    Returns
    -------
    For 'wilcox' / 't' / 'bimod' / 'LR' / 'negbinom' / 'poisson' / 'mast':
    DataFrame with columns p_val, avg_log2FC, pct.1, pct.2, p_val_adj
    (sorted by p_val).
    For 'roc': columns myAUC, avg_diff, power, avg_log2FC, pct.1, pct.2
    (sorted by power), with no p-value — matching Seurat.

    Notes
    -----
    **Divergence, 'negbinom' and 'poisson'.** Seurat's ``GLMDETest`` *drops* a
    gene from its output when the gene is detected in fewer than ``min.cells``
    (3) cells in **both** groups, or has zero variance across them; it flags
    those with a sentinel p-value of 2 and deletes the rows. Here they are
    returned with ``p_val = 1.0`` instead — no evidence rather than no row —
    which keeps the frame's gene set identical across every ``test_use`` and
    keeps ``p_val`` a p-value. The ``min_pct`` pre-filter already removes most
    such genes before either rule could fire.
    """
    assay_name = assay or seurat.active_assay
    assay_obj = seurat.assays[assay_name]
    cells = seurat.cell_names()
    idents = list(seurat.idents)

    # Resolve ident strings
    ident_1_set = {str(ident_1)} if isinstance(ident_1, str) else {str(i) for i in ident_1}
    if ident_2 is None:
        ident_2_set = {str(i) for i in set(idents) if str(i) not in ident_1_set}
    else:
        ident_2_set = {str(ident_2)} if isinstance(ident_2, str) else {str(i) for i in ident_2}

    # Cell indices for each group
    cells_1 = [c for c, i in zip(cells, idents) if str(i) in ident_1_set]
    cells_2 = [c for c, i in zip(cells, idents) if str(i) in ident_2_set]

    if not cells_1:
        raise ValueError(f"No cells found with ident {ident_1}.")
    if not cells_2:
        # `ident_2=None` means "every other ident", so name what was searched
        # rather than a parameter the caller never passed.
        raise ValueError(
            f"No cells found with ident {ident_2}." if ident_2 is not None
            else f"No cells left outside ident {ident_1} to compare against."
        )

    # Optional downsampling
    if max_cells_per_ident is not None:
        rng = np.random.default_rng(random_seed)
        if len(cells_1) > max_cells_per_ident:
            cells_1 = list(rng.choice(cells_1, max_cells_per_ident, replace=False))
        if len(cells_2) > max_cells_per_ident:
            cells_2 = list(rng.choice(cells_2, max_cells_per_ident, replace=False))

    # Get expression matrix for all genes (features × cells)
    data, feature_names = _get_expression_matrix(assay_obj, layer)

    cell_idx_map = {c: i for i, c in enumerate(cells)}
    idx_1 = [cell_idx_map[c] for c in cells_1]
    idx_2 = [cell_idx_map[c] for c in cells_2]

    # Column-slice each group and leave it sparse. A lazy layer indexes like a
    # sparse one and hands back a scipy CSC, so it takes the same branch -- the
    # dense fallback would materialise the whole store twice, once per group.
    #
    # Nothing here is densified. Both pre-filters below (`min_pct` and
    # `logfc_threshold`) are computable on the sparse matrices, and they are
    # what decides the handful of genes that a dense array is finally built for.
    if sp.issparse(data) or is_lazy(data):
        sub1 = data[:, idx_1]  # (features × n1)
        sub2 = data[:, idx_2]  # (features × n2)
    else:
        sub1 = np.asarray(data)[:, idx_1].astype(float)
        sub2 = np.asarray(data)[:, idx_2].astype(float)
    n1, n2 = sub1.shape[1], sub2.shape[1]

    # Restrict features
    if features is not None:
        feat_set = set(features)
        feat_mask = np.array([f in feat_set for f in feature_names])
    else:
        feat_mask = np.ones(len(feature_names), dtype=bool)

    # Percent cells expressing (> 0)
    pct1 = _row_pct_positive(sub1)
    pct2 = _row_pct_positive(sub2)

    # Pre-filter: gene must be expressed in at least min_pct of either group
    pct_mask = (pct1 >= min_pct) | (pct2 >= min_pct)
    combined_mask = feat_mask & pct_mask

    # Log2 fold change, matching Seurat 5's `log1pdata.mean.fxn` exactly:
    #   log2((sum(expm1(x)) + pseudocount) / n)
    # Data is log1p-normalized, so each cell is un-logged (expm1) before averaging.
    #
    # The pseudocount goes on the **sum**, not on the mean — it is one count added
    # to the whole group, worth 1/n on the mean scale, not 1. Adding it to the mean
    # instead (Seurat 4's `rowMeans(expm1(x)) + pseudocount`) floors every fold
    # change near zero: a gene seen in 0 % of one group and 24 % of the other
    # reads -1.26 that way against Seurat 5's -9.92. On pbmc3k that moved 98.9 %
    # of genes, and because `logfc_threshold` filters on this value it also
    # changed *which* genes came back — 2,298 against Seurat's 11,931 at 0.25.
    #
    # NOTE: the mean must be taken AFTER expm1, not before — expm1(mean(x)) is the
    # geometric-style mean and systematically compresses fold-changes (Jensen).
    group1_mean = (_row_expm1_sum(sub1) + PSEUDOCOUNT) / n1
    group2_mean = (_row_expm1_sum(sub2) + PSEUDOCOUNT) / n2
    avg_log2fc = np.log2(group1_mean) - np.log2(group2_mean)

    # Pre-filter by logfc_threshold
    if logfc_threshold > 0:
        fc_mask_arr = np.abs(avg_log2fc) >= logfc_threshold
        combined_mask = combined_mask & fc_mask_arr

    test_indices = np.where(combined_mask)[0]

    # The pre-filters are done, so this is where the dense arrays the per-gene
    # tests need get built — for the surviving genes only. `deseq2` is excluded
    # because it never looks at them; it aggregates the counts layer itself.
    if test_use != "deseq2" and len(test_indices) > 0:
        mat1 = _dense_rows(sub1, test_indices)  # (tested genes × n1)
        mat2 = _dense_rows(sub2, test_indices)  # (tested genes × n2)
    # Nothing below reads the sparse slices, and the per-gene loops they would
    # otherwise sit through run for seconds. Between them they hold about one
    # copy of the layer, so dropping them here is worth the line.
    del sub1, sub2

    # Per-cell covariates for the regression-based tests. Mirrors Seurat's
    # `DEmethods_latent()` — negbinom, poisson, MAST, LR.
    latent = None
    if latent_vars and test_use in ("LR", "negbinom", "poisson", "mast"):
        lat1 = seurat.meta_data.loc[cells_1, latent_vars].to_numpy(dtype=float)
        lat2 = seurat.meta_data.loc[cells_2, latent_vars].to_numpy(dtype=float)
        latent = np.vstack([lat1, lat2])

    # ---- ROC test: returns AUC / power, no p-value (matches Seurat) ----------
    if test_use == "roc":
        if len(test_indices) == 0:
            return pd.DataFrame(
                columns=["myAUC", "avg_diff", "power", "avg_log2FC", "pct.1", "pct.2"]
            )
        aucs = np.empty(len(test_indices))
        powers = np.empty(len(test_indices))
        avg_diff = np.empty(len(test_indices))
        for i in range(len(test_indices)):
            auc, power = _roc_auc(mat1[i, :], mat2[i, :])
            aucs[i] = auc
            powers[i] = power
            avg_diff[i] = mat1[i, :].mean() - mat2[i, :].mean()
        roc_res = pd.DataFrame(
            {
                "myAUC": aucs,
                "avg_diff": avg_diff,
                "power": powers,
                "avg_log2FC": avg_log2fc[test_indices],
                "pct.1": pct1[test_indices],
                "pct.2": pct2[test_indices],
            },
            index=[feature_names[i] for i in test_indices],
        )
        if only_pos:
            roc_res = roc_res[roc_res["avg_log2FC"] > 0]
        return roc_res.sort_values("power", ascending=False)

    if len(test_indices) == 0:
        return pd.DataFrame(
            columns=["p_val", "avg_log2FC", "pct.1", "pct.2", "p_val_adj"]
        )

    # ---- pseudobulk DESeq2: sample-level test, not per-cell -------------------
    if test_use == "deseq2":
        return _deseq2_pseudobulk(
            seurat, assay_obj, cells_1, cells_2, sample_col,
            feature_names, test_indices, pct1, pct2, only_pos,
        )

    # ---- p-value-based tests -------------------------------------------------
    p_vals = np.ones(len(test_indices))

    if test_use == "wilcox":
        for i in range(len(test_indices)):
            x1 = mat1[i, :]
            x2 = mat2[i, :]
            if x1.sum() == 0 and x2.sum() == 0:
                p_vals[i] = 1.0
            else:
                # mannwhitneyu (asymptotic) applies the tie correction and
                # continuity correction that base-R wilcox.test / presto use —
                # essential for scRNA data, which is dominated by zero ties.
                # scipy.stats.ranksums does NOT correct for ties.
                try:
                    _, p = mannwhitneyu(
                        x1, x2, alternative="two-sided",
                        use_continuity=True, method="asymptotic",
                    )
                except ValueError:
                    # Raised only when every value in both groups is identical.
                    p = 1.0
                p_vals[i] = p if not np.isnan(p) else 1.0
    elif test_use == "t":
        from scipy.stats import ttest_ind
        for i in range(len(test_indices)):
            x1 = mat1[i, :]
            x2 = mat2[i, :]
            _, p = ttest_ind(x1, x2, equal_var=False)
            p_vals[i] = p if not np.isnan(p) else 1.0
    elif test_use == "bimod":
        for i in range(len(test_indices)):
            p_vals[i] = _bimod_pvalue(mat1[i, :], mat2[i, :])
    elif test_use == "LR":
        group = np.concatenate([np.ones(n1), np.zeros(n2)])
        for i in range(len(test_indices)):
            expr = np.concatenate([mat1[i, :], mat2[i, :]])
            p_vals[i] = _lr_pvalue(expr, group, latent)
    elif test_use == "mast":
        group = np.concatenate([np.ones(n1), np.zeros(n2)])
        for i in range(len(test_indices)):
            expr = np.concatenate([mat1[i, :], mat2[i, :]])
            p_vals[i] = _mast_pvalue(expr, group, latent)
    elif test_use in ("negbinom", "poisson"):
        # Seurat's two GLMDETest families. Both read counts, not the data layer
        # — and restricted to the tested genes for the same reason as above.
        counts_mat, _ = _get_expression_matrix(assay_obj, "counts")
        if sp.issparse(counts_mat) or is_lazy(counts_mat):
            c1 = _dense_rows(counts_mat[:, idx_1], test_indices)
            c2 = _dense_rows(counts_mat[:, idx_2], test_indices)
        else:
            dense_counts = np.asarray(counts_mat)
            c1 = dense_counts[np.ix_(test_indices, np.asarray(idx_1))]
            c2 = dense_counts[np.ix_(test_indices, np.asarray(idx_2))]
        group = np.concatenate([np.ones(n1), np.zeros(n2)])
        glm_test = _negbinom_pvalue if test_use == "negbinom" else _poisson_pvalue
        for i in range(len(test_indices)):
            cnts = np.concatenate([c1[i, :], c2[i, :]])
            p_vals[i] = glm_test(cnts, group, latent)
    else:
        raise ValueError(
            f"Unsupported test_use: {test_use!r}. Use 'wilcox', 't', 'bimod', "
            "'LR', 'negbinom', 'poisson', 'mast', 'deseq2', or 'roc'."
        )

    # Bonferroni correction (Seurat default: multiply by total gene count)
    n_total = len(feature_names)
    p_val_adj = np.minimum(p_vals * n_total, 1.0)

    results = pd.DataFrame(
        {
            "p_val": p_vals,
            "avg_log2FC": avg_log2fc[test_indices],
            "pct.1": pct1[test_indices],
            "pct.2": pct2[test_indices],
            "p_val_adj": p_val_adj,
        },
        index=[feature_names[i] for i in test_indices],
    )

    if only_pos:
        results = results[results["avg_log2FC"] > 0]

    return results.sort_values("p_val")


def find_all_markers(
    seurat,
    assay: Optional[str] = None,
    layer: Optional[str] = None,
    test_use: str = "wilcox",
    only_pos: bool = False,
    min_pct: float = 0.1,
    logfc_threshold: float = 0.25,
    sample_col: Optional[str] = None,
    max_cells_per_ident: Optional[int] = None,
    random_seed: int = 1,
    return_thresh: float = 1e-2,
) -> pd.DataFrame:
    """Find marker genes for each cluster vs all others.

    Mirrors R's FindAllMarkers(pbmc, only.pos = TRUE).

    Returns a single DataFrame with an extra 'cluster' column.

    ``return_thresh`` is Seurat's ``return.thresh``: only genes with
    ``p_val < return_thresh`` are returned (for ``test_use="roc"``, only genes
    whose ``myAUC`` is further than ``return_thresh`` from 0.5 in either
    direction, since ROC reports no p-value). Pass ``None`` for the unfiltered
    table. Without it truecell returned every gene that survived the pct and
    logfc pre-filters, including plainly non-significant ones: on PBMC 3k that
    was 3,036 rows against Seurat's 3,446 spread over one fewer cluster, and on
    the two clusters whose membership matched Seurat exactly the filtered table
    reproduces Seurat's gene set exactly (151 and 242 genes).

    Rows are ordered by ``p_val`` ascending and then ``avg_log2FC`` descending
    within each cluster, matching Seurat's ``order(gde$p_val, -gde[, 2])``.
    The tie-break matters: Wilcoxon p-values tie at 0 for the strongest
    markers, so without it "the top 10 markers" depends on incoming row order.
    """
    clusters = sorted(set(str(i) for i in seurat.idents), key=_ident_sort_key)
    all_results = []

    for cluster in clusters:
        try:
            df = find_markers(
                seurat,
                ident_1=cluster,
                ident_2=None,
                assay=assay,
                layer=layer,
                test_use=test_use,
                only_pos=only_pos,
                min_pct=min_pct,
                logfc_threshold=logfc_threshold,
                sample_col=sample_col,
                max_cells_per_ident=max_cells_per_ident,
                random_seed=random_seed,
            )
            if len(df) > 0:
                df = df.copy()
                df["cluster"] = cluster
                df["gene"] = df.index
                all_results.append(df)
        except Exception as e:
            print(f"Warning: cluster {cluster} marker finding failed: {e}")

    if not all_results:
        return pd.DataFrame(
            columns=["p_val", "avg_log2FC", "pct.1", "pct.2", "p_val_adj", "cluster", "gene"]
        )

    combined = pd.concat(all_results, axis=0)
    if return_thresh is not None:
        if test_use == "roc":
            # ROC has no p-value; Seurat thresholds on distance from chance.
            auc = combined["myAUC"]
            combined = combined[(auc > return_thresh) | (auc < 1 - return_thresh)]
        else:
            combined = combined[combined["p_val"] < return_thresh]
    if test_use == "roc":
        cols = ["cluster", "gene", "myAUC", "avg_diff", "power", "avg_log2FC",
                "pct.1", "pct.2"]
        cols = [c for c in cols if c in combined.columns]
        return combined[cols].sort_values(["cluster", "myAUC"], ascending=[True, False])
    combined = combined[["cluster", "gene", "p_val", "avg_log2FC", "pct.1", "pct.2", "p_val_adj"]]
    return combined.sort_values(["cluster", "p_val", "avg_log2FC"],
                                ascending=[True, True, False])


def find_conserved_markers(
    seurat,
    ident_1: Union[str, list[str]],
    grouping_var: str,
    ident_2: Optional[Union[str, list[str]]] = None,
    assay: Optional[str] = None,
    layer: Optional[str] = None,
    test_use: str = "wilcox",
    only_pos: bool = False,
    min_pct: float = 0.1,
    logfc_threshold: float = 0.25,
    features: Optional[list[str]] = None,
) -> pd.DataFrame:
    """Find markers conserved across the levels of a grouping variable.

    Mirrors R's ``FindConservedMarkers(obj, ident.1, grouping.var = "stim")``:
    runs :func:`find_markers` for ``ident_1`` vs ``ident_2`` independently within
    each level of ``grouping_var``, keeps only genes detected as markers in
    *every* level, and combines their per-level p-values with Fisher's method
    (:func:`scipy.stats.combine_pvalues`).

    Every argument not listed below is forwarded verbatim to
    :func:`find_markers`.

    Parameters
    ----------
    ident_1      : cluster label(s) for group 1.
    grouping_var : metadata column whose levels define the independent
                   comparisons (e.g. condition, batch, donor).
    ident_2      : cluster label(s) for group 2 (None = all other cells).

    Returns
    -------
    DataFrame indexed by gene with, for each level ``g``, the columns
    ``{g}_p_val, {g}_avg_log2FC, {g}_pct.1, {g}_pct.2, {g}_p_val_adj`` plus
    ``max_pval`` (worst per-level p-value) and ``combined_p_val`` (Fisher-combined
    across levels), sorted by ``combined_p_val``. Only genes that are markers in
    all levels are returned.
    """
    from scipy.stats import combine_pvalues

    if grouping_var not in seurat.meta_data.columns:
        raise KeyError(
            f"grouping_var {grouping_var!r} not found in meta_data "
            f"(columns: {list(seurat.meta_data.columns)})."
        )

    cells = seurat.cell_names()
    group_of = seurat.meta_data.loc[cells, grouping_var].astype(str)
    levels = sorted(group_of.unique())

    per_level: dict[str, pd.DataFrame] = {}
    for level in levels:
        level_cells = [c for c, g in zip(cells, group_of) if g == level]
        sub = seurat.subset(cells=level_cells)
        try:
            df = find_markers(
                sub,
                ident_1=ident_1,
                ident_2=ident_2,
                assay=assay,
                layer=layer,
                test_use=test_use,
                only_pos=only_pos,
                min_pct=min_pct,
                logfc_threshold=logfc_threshold,
                features=features,
            )
        except ValueError as e:
            warnings.warn(
                f"Skipping {grouping_var}={level!r}: {e}", RuntimeWarning, stacklevel=2
            )
            continue
        if len(df) > 0:
            per_level[level] = df

    if not per_level:
        raise ValueError(
            f"No level of {grouping_var!r} yielded markers for the requested comparison."
        )

    # Genes must be markers in every retained level.
    common = set.intersection(*(set(df.index) for df in per_level.values()))

    used = list(per_level)
    cols: dict[str, pd.Series] = {}
    for level in used:
        df = per_level[level].loc[list(common)]
        for c in df.columns:
            cols[f"{level}_{c}"] = df[c]
    result = pd.DataFrame(cols, index=list(common))

    if test_use == "roc":
        # ROC has no p-value; conservation is summarised by the min power.
        power_cols = [f"{level}_power" for level in used]
        result["min_power"] = result[power_cols].min(axis=1)
        return result.sort_values("min_power", ascending=False)

    pval_cols = [f"{level}_p_val" for level in used]
    result["max_pval"] = result[pval_cols].max(axis=1)
    if len(used) == 1:
        result["combined_p_val"] = result[pval_cols[0]]
    else:
        result["combined_p_val"] = [
            combine_pvalues(result.loc[g, pval_cols].to_numpy(dtype=float),
                            method="fisher").pvalue
            for g in result.index
        ]
    return result.sort_values("combined_p_val")


def _deseq2_pseudobulk(
    seurat,
    assay_obj,
    cells_1: list[str],
    cells_2: list[str],
    sample_col: Optional[str],
    feature_names: list[str],
    test_indices: np.ndarray,
    pct1: np.ndarray,
    pct2: np.ndarray,
    only_pos: bool,
) -> pd.DataFrame:
    """Pseudobulk DESeq2 test (Seurat's ``test.use = "DESeq2"``).

    Sums raw counts to one pseudobulk profile per (group, ``sample_col``) — the
    same aggregation as :func:`truecell.aggregate.aggregate_expression` — then fits
    a DESeq2 model with design ``~condition`` and contrasts group 1 vs group 2.
    A positive ``avg_log2FC`` (DESeq2's ``log2FoldChange``) means up in group 1.
    """
    try:
        from pydeseq2.dds import DeseqDataSet
        from pydeseq2.ds import DeseqStats
    except ImportError as e:  # pragma: no cover - exercised only without the dep
        raise ImportError(
            "test_use='deseq2' requires pydeseq2. Install with "
            "`pip install truecell[deseq2]`."
        ) from e

    if sample_col is None:
        raise ValueError(
            "test_use='deseq2' is a pseudobulk test and requires sample_col — the "
            "replicate/donor column to aggregate cells into per-sample profiles."
        )
    if sample_col not in seurat.meta_data.columns:
        raise KeyError(f"sample_col {sample_col!r} not found in meta_data.")

    counts_mat, _ = _get_expression_matrix(assay_obj, "counts")
    counts_sub = counts_mat[test_indices, :]  # tested genes × all cells
    cell_pos = {c: i for i, c in enumerate(seurat.cell_names())}
    samples = seurat.meta_data[sample_col].astype(str)
    gene_names = [feature_names[i] for i in test_indices]

    def _pseudobulk(group_cells: list[str], cond: str) -> dict[str, np.ndarray]:
        by_sample: dict[str, list[int]] = {}
        for c in group_cells:
            by_sample.setdefault(samples[c], []).append(cell_pos[c])
        cols: dict[str, np.ndarray] = {}
        for samp, idxs in by_sample.items():
            summed = counts_sub[:, idxs].sum(axis=1)
            cols[f"{cond}::{samp}"] = np.asarray(summed).ravel()
        return cols

    pb = {**_pseudobulk(cells_1, "group1"), **_pseudobulk(cells_2, "group2")}
    sample_names = list(pb)
    condition = ["group1" if s.startswith("group1::") else "group2" for s in sample_names]

    n1, n2 = condition.count("group1"), condition.count("group2")
    if n1 < 2 or n2 < 2:
        warnings.warn(
            f"DESeq2 pseudobulk has {n1} vs {n2} replicate(s) in {sample_col!r}; "
            "dispersion estimates are unreliable without ≥2 replicates per group.",
            RuntimeWarning,
            stacklevel=2,
        )

    # pydeseq2 wants samples × genes, integer counts.
    counts_df = pd.DataFrame(
        np.column_stack([pb[s] for s in sample_names]).T.astype(int),
        index=sample_names,
        columns=gene_names,
    )
    metadata = pd.DataFrame({"condition": condition}, index=sample_names)

    dds = DeseqDataSet(counts=counts_df, metadata=metadata, design="~condition", quiet=True)
    dds.deseq2()
    stat = DeseqStats(dds, contrast=["condition", "group1", "group2"], quiet=True)
    stat.summary()
    res = stat.results_df.reindex(gene_names)

    out = pd.DataFrame(
        {
            "p_val": res["pvalue"].fillna(1.0).to_numpy(),
            "avg_log2FC": res["log2FoldChange"].fillna(0.0).to_numpy(),
            "pct.1": pct1[test_indices],
            "pct.2": pct2[test_indices],
            "p_val_adj": res["padj"].fillna(1.0).to_numpy(),
        },
        index=gene_names,
    )
    if only_pos:
        out = out[out["avg_log2FC"] > 0]
    return out.sort_values("p_val")


# ------------------------------------------------------------------
# Helper
# ------------------------------------------------------------------

def _layer_aliases(layer: Optional[str]) -> tuple[str, ...]:
    """The spellings a layer name can arrive as.

    Seurat's layer is ``scale.data`` and the Python API argument is
    ``scale_data``; both reach here, and the Assay5 layer dict is keyed with the
    dotted form. Matching only one spelling means the other misses the dict and
    falls through to the ``data`` fallback below — silently, with the right
    shape, which is the whole problem.
    """
    if layer is None:
        return ()
    if layer in ("scale_data", "scale.data"):
        return ("scale.data", "scale_data")
    return (layer,)


def _get_expression_matrix(assay_obj, layer: Optional[str]):
    """Return (matrix features×cells, feature_names) using best available layer.

    The names returned are the **layer's own**, not the assay's. Only
    ``scale.data`` holds a subset — ``scale_data()`` defaults to the variable
    features, as R's ``ScaleData`` does — so handing back the full assay feature
    list alongside a matrix a fraction of its height mislabels every row. That is
    the defect fixed in ``reduction.py`` under #66; this function had the same
    one, reachable through ``find_markers(layer=...)`` and the two aggregation
    functions.
    """
    mat, feature_names, _ = _get_expression_layer(assay_obj, layer)
    return mat, feature_names


def _get_expression_layer(assay_obj, layer: Optional[str]):
    """:func:`_get_expression_matrix`, plus the layer's own cell names.

    For callers that find columns by cell. An object's ``cell_names()`` name its
    metadata rows, which is not the same list as a layer's columns once the two
    have drifted apart, and a column found by position in one then reads another
    cell in the other.
    """
    from .assay5 import Assay5

    if isinstance(assay_obj, Assay5):
        for key in (*_layer_aliases(layer), "data", "counts"):
            if key in assay_obj.layers:
                features = assay_obj._layer_features.get(key, assay_obj._all_feature_names)
                cells = assay_obj._layer_cells.get(key, assay_obj._all_cell_names)
                return assay_obj.layers[key], list(features), list(cells)
        raise ValueError("No expression data layer found in Assay5.")
    feature_names = assay_obj._feature_names
    cell_names = list(assay_obj._cell_names)
    from ._sparse import is_matrix_empty
    if layer == "counts":
        return assay_obj.counts, feature_names, cell_names
    if layer in ("scale_data", "scale.data"):
        return assay_obj.scale_data, assay_obj.features("scale_data"), cell_names
    # Prefer log-normalized data
    if not is_matrix_empty(assay_obj.data):
        return assay_obj.data, feature_names, cell_names
    return assay_obj.counts, feature_names, cell_names

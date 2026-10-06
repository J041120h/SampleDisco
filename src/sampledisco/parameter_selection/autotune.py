"""Sample-embedding hyperparameter autotune.

Bayesian search over the RMD weight (`alpha_only` scope by default) using the
`multi_metric_proxy` ensemble. Adaptive — the proxy ensemble drops components
the data can't support:

  - If the dataset has no usable batch column → drop iLISI(batch) and
    ASW(batch) proxies (they need a discrete batch label).
  - If the dataset has no grouping/trajectory label → drop supervised proxies
    (CCA, SPS, CV-kNN, pseudotime-Spearman).
  - If neither → emit a warning and short-circuit with fixed defaults.

``scoring="ilisi_label"`` is the two-term variant: one biology term (grouping
tracking: CCA or categorical PC-R²) and one batch term (iLISI), equally weighted.

Generalized version of `wire_autotune_dualembed_v2.py`. No dataset-specific
paths; all data flows through the same `compute_sample_embedding` primitives
in `sample_embedding/blocks.py`.
"""

from __future__ import annotations

import math
import os
import time
import warnings
from typing import Callable, Dict, List, Optional, Tuple, Union

import numpy as np
import pandas as pd
from anndata import AnnData
from sklearn.cluster import MiniBatchKMeans
from sklearn.cross_decomposition import CCA
from sklearn.decomposition import PCA
from sklearn.gaussian_process import GaussianProcessRegressor
from sklearn.gaussian_process.kernels import ConstantKernel, Matern, WhiteKernel
from sklearn.linear_model import LinearRegression
from sklearn.metrics import silhouette_score
from sklearn.model_selection import KFold
from scipy.spatial.distance import pdist, squareform
from scipy.stats import norm, spearmanr

from sampledisco.sample_embedding.blocks import (
    assemble_units,
    build_emb_from_blocks,
    composition_per_unit,
    derive_weights,
    loo_rmd,
    resolve_rmd_weight,
    save_embedding_to_h5ad,
    soft_assign,
    warn_if_stale_embedding,
)
from sampledisco.utils.embedding_keys import resolve_comp_key, resolve_rmd_key


# Only the ceiling moved (10.0 -> 100.0). Datasets whose signal lives in the RMD
# block were being truncated by the old ceiling: a dense sweep puts the optimum
# at alpha = 16 on the 1M-scBloodNL stimulation time-course, and several saved
# runs (covid ATAC, covid 279, unpaired paper) had returned alpha pinned at 10.0.
# The floor stays at 0.1: no dataset has ever optimised against it, and on a
# composition-dominated cohort the objective is flat below ~1.5, so a lower floor
# only lets alpha drift down until the RMD block is numerically absent.
DEFAULT_ALPHA_BOUNDS = (0.1, 100.0)


# ============================================================ #
# Pre-compute blocks (composition + RMD) once; sweep weights    #
# ============================================================ #
def build_blocks(
    adata: AnnData,
    sample_col: str,
    celltype_col: str,
    comp_emb_key: Optional[str] = None,
    rmd_emb_key: Optional[str] = None,
    modality_col: Optional[str] = None,
    batch_col: Optional[str] = None,
    grouping_col: Optional[str] = None,
    medium_K: int = 120,
    fine_K: int = 300,
    rmd_dim: int = 8,
    seed: int = 42,
    verbose: bool = True,
) -> Dict:
    """Build composition + RMD blocks once. Returns a dict the inner loop reuses."""
    comp_key = resolve_comp_key(adata, comp_emb_key, context="autotune")
    rmd_key = resolve_rmd_key(adata, rmd_emb_key, comp_key=comp_key,
                              context="autotune")

    units, unit_cellids, unit_ids, unit_groups, unit_batches, all_cellids, Z_comp = \
        assemble_units(adata, sample_col, comp_key,
                       modality_col=modality_col, batch_col=batch_col)
    n_units = len(units)
    cellid_idx = {cid: i for i, cid in enumerate(all_cellids)}

    cell_type = adata.obs[celltype_col].astype(str).values
    unique_cts = sorted(set(cell_type))
    K_c = len(unique_cts)

    # A1: hard cell-type-label composition (one-hot, no clustering)
    L1 = {ct: i for i, ct in enumerate(unique_cts)}
    soft1 = np.zeros((Z_comp.shape[0], K_c), dtype=np.float32)
    for i, ct in enumerate(cell_type):
        soft1[i, L1[ct]] = 1.0
    unit_cellids_list = [unit_cellids[uid] for uid in unit_ids]
    A1 = composition_per_unit(unit_cellids_list, soft1, cellid_idx)

    K_med = min(medium_K, max(2, Z_comp.shape[0] // 200))
    if verbose:
        print(f"[autotune.build_blocks] K-means K={K_med}...")
    km_med = MiniBatchKMeans(n_clusters=K_med, random_state=seed,
                              batch_size=4096, n_init=5, max_iter=200).fit(Z_comp)
    soft2 = soft_assign(Z_comp, km_med.cluster_centers_)
    A2 = composition_per_unit(unit_cellids_list, soft2, cellid_idx)

    K_fine = min(fine_K, max(2, Z_comp.shape[0] // 100))
    if verbose:
        print(f"[autotune.build_blocks] K-means K={K_fine}...")
    km_fine = MiniBatchKMeans(n_clusters=K_fine, random_state=seed + 1,
                                batch_size=4096, n_init=5, max_iter=200).fit(Z_comp)
    soft3 = soft_assign(Z_comp, km_fine.cluster_centers_)
    A3 = composition_per_unit(unit_cellids_list, soft3, cellid_idx)

    # RMD
    Z_rmd = np.asarray(adata.obsm[rmd_key], dtype=np.float32)
    rmd_units = []
    for uid, group in zip(unit_ids, unit_groups):
        cids = unit_cellids[uid]
        idxs = [cellid_idx[c] for c in cids if c in cellid_idx]
        rmd_units.append((uid, group, Z_rmd[idxs]))
    coarse_label_map = dict(zip(all_cellids, cell_type))
    RMD = loo_rmd(rmd_units, unit_cellids, coarse_label_map,
                    max_dim_per_cluster=rmd_dim, seed=seed,
                    loo=True, verbose=False)

    # Sample-level metadata for scoring
    if grouping_col is not None and grouping_col in adata.obs.columns:
        grp_series = adata.obs.groupby(sample_col, observed=True)[grouping_col].agg(
            lambda s: s.dropna().iloc[0] if s.dropna().size else np.nan
        )
        # Align to unit_ids — for MO uids are "{sample}_{modality}", so try suffix-strip
        grouping = []
        for uid in unit_ids:
            val = grp_series.get(uid, np.nan)
            if pd.isna(val):
                # try without modality suffix
                for s in grp_series.index:
                    if uid.startswith(str(s) + "_"):
                        val = grp_series[s]
                        break
            grouping.append(val)
        grouping_arr = np.asarray(grouping)
    else:
        grouping_arr = None

    batch_arr = (np.asarray(unit_batches) if unit_batches is not None
                  else np.asarray(unit_groups))
    has_batch = len(set(batch_arr.tolist())) > 1
    has_grouping = grouping_arr is not None and len(
        set(x for x in grouping_arr.tolist() if pd.notna(x))
    ) > 1

    return dict(
        A1=A1, A2=A2, A3=A3, RMD=RMD,
        K_c=K_c, K_med=K_med, K_fine=K_fine,
        unit_ids=unit_ids, unit_groups=unit_groups, unit_batches=unit_batches,
        n_units=n_units, grouping=grouping_arr, batch=batch_arr,
        has_batch=has_batch, has_grouping=has_grouping,
        comp_emb_key=comp_key, rmd_emb_key=rmd_key,
    )


# ============================================================ #
# Scoring functions                                              #
# ============================================================ #
def _is_categorical_target(target) -> bool:
    """True when ``target`` cannot be cast to a float array — i.e. its
    values are strings / categorical labels. Used by the scorer dispatcher
    to pick between CCA (numeric) and PC-R² (categorical)."""
    try:
        np.asarray(target).astype(float)
        return False
    except (ValueError, TypeError):
        return True


def _cca_corr(emb, target):
    """First canonical correlation between ``emb`` (n × d) and a NUMERIC
    1-D ``target`` (continuous grouping; e.g. age, severity score).

    Categorical targets should NOT call this — the dispatcher routes them
    to ``_pc_r2_categorical`` instead. If a non-castable target is passed
    here we return 0 as a defensive fallback rather than mis-interpret it.
    """
    e = np.asarray(emb)
    try:
        t = np.asarray(target, dtype=float).reshape(-1, 1)
    except (ValueError, TypeError):
        return 0.0
    keep = ~np.isnan(t.flatten())
    if keep.sum() < 4:
        return 0.0
    e = e[keep]
    t = t[keep]
    n_pc = min(10, e.shape[1], e.shape[0] - 1)
    if n_pc < 1:
        return 0.0
    Xr = PCA(n_components=n_pc, random_state=42).fit_transform(e)
    try:
        c = CCA(n_components=1, max_iter=500).fit(Xr, t)
        U, V = c.transform(Xr, t)
        r = float(abs(np.corrcoef(U[:, 0], V[:, 0])[0, 1]))
        return r if np.isfinite(r) else 0.0
    except Exception:
        return 0.0


def _pc_r2_categorical(emb, target):
    """Mean R² of top-K embedding PCs regressed on one-hot ``target``.

    Principled categorical analogue to CCA: how much of the linear
    variance in the embedding's leading PCs is explained by the categorical
    label (multi-class ANOVA framing). Bounded [0, 1] — comparable to the
    canonical correlation magnitude used by ``_cca_corr`` so both can sit in
    the same min-max-normalised scorer ensemble.
    """
    e = np.asarray(emb)
    arr = np.asarray(target)
    keep = pd.notna(arr)
    if keep.sum() < 4:
        return 0.0
    e = e[keep]
    Y = pd.get_dummies(pd.Series(arr[keep].astype(str))).values.astype(float)
    if Y.shape[1] < 2:
        return 0.0
    n_pc = min(10, e.shape[1], e.shape[0] - 1)
    if n_pc < 1:
        return 0.0
    Xr = PCA(n_components=n_pc, random_state=42).fit_transform(e)
    r2s = []
    for i in range(n_pc):
        try:
            lr = LinearRegression().fit(Y, Xr[:, i])
            r2s.append(max(0.0, float(lr.score(Y, Xr[:, i]))))
        except Exception:
            continue
    return float(np.mean(r2s)) if r2s else 0.0


def _ilisi_norm(emb, labels, k=15):
    """Normalised iLISI: mean k-NN inverse Simpson index divided by n_labels. Range [0, 1]; higher = better batch mixing."""
    e = np.asarray(emb)
    labs = np.array([str(l) for l in labels])
    n = e.shape[0]
    uniq = sorted(set(labs))
    if len(uniq) < 2 or n < k + 1:
        return 0.0
    D = squareform(pdist(e))
    np.fill_diagonal(D, np.inf)
    lis = np.zeros(n)
    for i in range(n):
        nn = np.argpartition(D[i], k)[:k]
        _, counts = np.unique(labs[nn], return_counts=True)
        p = counts / counts.sum()
        lis[i] = 1.0 / np.sum(p ** 2)
    return float(np.clip(np.mean(lis) / len(uniq), 0.0, 1.0))


def _asw_safe(emb, labels):
    """Silhouette score guarded against single-member groups; returns 0 on failure."""
    e = np.asarray(emb)
    labs = np.array([str(l) for l in labels])
    if len(set(labs)) < 2 or e.shape[0] < 4:
        return 0.0
    if any(list(labs).count(b) < 2 for b in set(labs)):
        return 0.0
    try:
        return float(silhouette_score(e, labs, metric="euclidean"))
    except Exception:
        return 0.0


def _sps_continuous(emb, target, q=4):
    """Between-group / within-group mean pairwise distance ratio.

    For numeric ``target`` we bin into ``q`` quartiles via ``pd.qcut``.
    For categorical (string) ``target`` we use the unique levels directly
    as bins (no quartile binning needed).
    """
    e = np.asarray(emb)
    arr = np.asarray(target)
    try:
        t = arr.astype(float)
        keep = ~np.isnan(t)
        if keep.sum() < 4:
            return 0.0
        e = e[keep]; t = t[keep]
        try:
            bins = pd.qcut(pd.Series(t), q=q, labels=False, duplicates="drop").values
        except Exception:
            return 0.0
    except (ValueError, TypeError):
        keep = pd.notna(arr)
        if keep.sum() < 4:
            return 0.0
        e = e[keep]
        bins = pd.factorize(pd.Series(arr[keep].astype(str)))[0]
    if len(set(bins)) < 2:
        return 0.0
    D = squareform(pdist(e))
    n = e.shape[0]
    iu = np.triu_indices(n, k=1)
    eq = bins[iu[0]] == bins[iu[1]]
    if eq.sum() < 1 or (~eq).sum() < 1:
        return 0.0
    w = D[iu][eq].mean()
    b = D[iu][~eq].mean()
    return float(b / max(w, 1e-9))


def _cv_knn_neg_mae(emb, target, k=3, n_splits=5):
    """Negative normalised MAE of k-NN regression on ``target``. Higher (less negative) = better label prediction."""
    e = np.asarray(emb)
    t = np.asarray(target, dtype=float)
    keep = ~np.isnan(t)
    if keep.sum() < n_splits + k:
        return 0.0
    e = e[keep]
    t = t[keep]
    kf = KFold(n_splits=n_splits, shuffle=True, random_state=42)
    mae_sum = 0.0
    n_sum = 0
    for tr, te in kf.split(e):
        D = np.linalg.norm(e[te][:, None] - e[tr][None, :], axis=-1)
        idx = np.argpartition(D, min(k, D.shape[1] - 1), axis=1)[:, :k]
        preds = t[tr][idx].mean(axis=1)
        mae_sum += float(np.sum(np.abs(preds - t[te])))
        n_sum += len(te)
    mae = mae_sum / max(n_sum, 1)
    std = float(np.std(t) + 1e-9)
    return -float(mae / std)


def _pseudotime_spearman(emb, target):
    """|Spearman(PC1(emb), target)|; measures pseudotime alignment of the embedding's leading axis."""
    e = np.asarray(emb)
    t = np.asarray(target, dtype=float)
    keep = ~np.isnan(t)
    if keep.sum() < 4:
        return 0.0
    e = e[keep]
    t = t[keep]
    pt = PCA(n_components=1, random_state=42).fit_transform(e).flatten()
    rho, _ = spearmanr(pt, t)
    return float(abs(rho)) if np.isfinite(rho) else 0.0


def _minmax(x, lo, hi):
    if hi <= lo:
        return 0.5
    return float(np.clip((x - lo) / (hi - lo), 0.0, 1.0))


SCORING_BOUNDS = {
    "cca":              (0.0, 1.0),    # numeric grouping → first canonical correlation
    # Categorical grouping: mean top-PC R² regressed on one-hot label.
    # Empirically lower-magnitude than CCA — only the few PCs that span the
    # discriminant direction contribute, the rest dilute the mean. Bounds
    # calibrated so a "good" categorical score (≈0.20) lands near 0.8 after
    # min-max normalisation in multi_metric_proxy.
    "pc_r2_categorical":(0.0, 0.25),
    "ilisi_norm":       (0.0, 1.0),
    "sps":              (1.0, 3.0),
    "neg_asw_batch":    (-0.5, 0.5),
}


def make_scorer(name: str, meta: Dict, lam: float = 0.5) -> Callable[[np.ndarray], float]:
    """Closure: returns score_fn(emb_array) → float.

    Gates the underlying components based on data availability:
      - `multi_metric_proxy` only includes proxies whose required data is present.
      - If both batch and grouping are missing, the scorer returns 0 (caller
        should detect this and short-circuit).
    """
    grouping = meta.get("grouping")
    batch = meta.get("batch")
    has_grouping = bool(meta.get("has_grouping"))
    has_batch = bool(meta.get("has_batch"))
    grouping_is_categorical = has_grouping and _is_categorical_target(grouping)

    # ``cca`` is the user-facing scorer name for "embedding tracks grouping".
    # For continuous grouping we use the proper CCA first canonical
    # correlation; for categorical grouping we use mean top-PC R² regressed
    # on one-hot label (a proper multi-class ANOVA framing). Both are
    # bounded [0, 1] with higher = better.
    def _grouping_tracking_score(emb):
        if grouping_is_categorical:
            return _pc_r2_categorical(emb, grouping)
        return _cca_corr(emb, grouping)

    if name == "cca":
        if not has_grouping:
            return lambda emb: 0.0
        return _grouping_tracking_score
    if name == "ilisi_batch":
        if not has_batch:
            return lambda emb: 0.0
        return lambda emb: _ilisi_norm(emb, batch)
    if name == "sps":
        if not has_grouping:
            return lambda emb: 0.0
        return lambda emb: _sps_continuous(emb, grouping)
    if name == "neg_asw_batch":
        if not has_batch:
            return lambda emb: 0.0
        return lambda emb: -_asw_safe(emb, batch)
    if name == "cv_knn_severity":
        if not has_grouping:
            return lambda emb: 0.0
        return lambda emb: _cv_knn_neg_mae(emb, grouping)
    if name == "pseudotime_spearman":
        if not has_grouping:
            return lambda emb: 0.0
        return lambda emb: _pseudotime_spearman(emb, grouping)

    if name == "sev_minus_batch":
        return lambda emb: (
            (_grouping_tracking_score(emb) if has_grouping else 0.0)
            - lam * (_asw_safe(emb, batch) if has_batch else 0.0)
        )

    if name in ("multi_metric_proxy", "auto", "ilisi_label"):
        two_term = name == "ilisi_label"
        components: List[Callable[[np.ndarray], float]] = []
        if has_grouping:
            tracking_key = "pc_r2_categorical" if grouping_is_categorical else "cca"
            components.append(
                lambda emb: _minmax(_grouping_tracking_score(emb),
                                    *SCORING_BOUNDS[tracking_key]))
            if not two_term:
                components.append(lambda emb: _minmax(_sps_continuous(emb, grouping), *SCORING_BOUNDS["sps"]))
        if has_batch:
            components.append(lambda emb: _minmax(_ilisi_norm(emb, batch), *SCORING_BOUNDS["ilisi_norm"]))
            if not two_term:
                components.append(lambda emb: _minmax(-_asw_safe(emb, batch), *SCORING_BOUNDS["neg_asw_batch"]))
        if not components:
            return lambda emb: 0.0

        def f(emb):
            vals = [c(emb) for c in components]
            return float(np.mean(vals))
        return f

    raise ValueError(f"unknown scoring: {name}")


# ============================================================ #
# Search strategies                                              #
# ============================================================ #
def _log10_bounds(bounds: Tuple[float, float]) -> Tuple[float, float]:
    """Map an alpha interval to log10 space, guarding against a non-positive low end."""
    lo, hi = float(bounds[0]), float(bounds[1])
    if hi <= 0:
        raise ValueError(f"alpha_bounds upper limit must be positive, got {hi}")
    lo = max(lo, hi * 1e-6)
    return math.log10(lo), math.log10(hi)


def search_grid(objective: Callable, alpha_grid: Optional[List[float]] = None,
                bounds: Optional[Tuple[float, float]] = None, n: int = 15):
    """Exhaustive grid search. Returns (best_alpha, best_score, trace).

    With ``alpha_grid`` the caller's points are used verbatim. Otherwise a
    log-spaced grid of ``n`` points is built from ``bounds`` — alpha is a scale
    parameter, so equal spacing in log10 gives each order of magnitude the same
    number of probes.
    """
    if alpha_grid is None:
        if bounds is None:
            raise ValueError("search_grid needs alpha_grid or bounds")
        t_lo, t_hi = _log10_bounds(bounds)
        alpha_grid = [float(10.0 ** t) for t in np.linspace(t_lo, t_hi, n)]
    trace = []
    best = None
    for a in alpha_grid:
        s = objective(a)
        trace.append((a, s))
        if best is None or s > best[1]:
            best = (a, s)
    return best[0], best[1], trace


def search_golden(objective: Callable, bounds=DEFAULT_ALPHA_BOUNDS, max_iter=12):
    """Golden-section search over log10(alpha) for a unimodal objective.

    Returns (best_alpha, best_score, trace); the trace is in alpha, not log10.
    """
    phi = (1 + math.sqrt(5)) / 2
    a, b = _log10_bounds(bounds)
    resphi = 2 - phi
    x1 = a + resphi * (b - a)
    x2 = b - resphi * (b - a)
    f1 = objective(10.0 ** x1)
    f2 = objective(10.0 ** x2)
    trace = [(10.0 ** x1, f1), (10.0 ** x2, f2)]
    for _ in range(max_iter):
        if f1 > f2:
            b = x2
            x2 = x1
            f2 = f1
            x1 = a + resphi * (b - a)
            f1 = objective(10.0 ** x1)
            trace.append((10.0 ** x1, f1))
        else:
            a = x1
            x1 = x2
            f1 = f2
            x2 = b - resphi * (b - a)
            f2 = objective(10.0 ** x2)
            trace.append((10.0 ** x2, f2))
    best = max(trace, key=lambda x: x[1])
    return best[0], best[1], trace


def _gp_ei(gp, X_grid, y_best, xi=0.01):
    """Expected Improvement acquisition over ``X_grid`` given fitted GP and current best ``y_best``."""
    mu, sigma = gp.predict(X_grid, return_std=True)
    with np.errstate(divide="warn"):
        imp = mu - y_best - xi
        Z = imp / np.where(sigma > 1e-12, sigma, 1e-12)
        ei = imp * norm.cdf(Z) + sigma * norm.pdf(Z)
        ei[sigma < 1e-12] = 0
    return ei


def search_bayesian(objective: Callable, bounds=DEFAULT_ALPHA_BOUNDS,
                     n_init=5, n_iter=10, seed=42):
    """GP-EI Bayesian optimisation over log10(alpha).

    Seeds with ``n_init`` log-spaced evaluations, then acquires via Expected
    Improvement on a log-spaced grid. Returns (best_alpha, best_score, trace),
    with the trace reported in alpha rather than log10.

    The search runs in log space because alpha is a scale parameter: seeding
    linearly over, say, [0.01, 1000] would place the first five probes at
    0.01/250/500/750/1000 and never examine the sub-unit region where the
    composition-dominated datasets have their optimum.
    """
    rng = np.random.default_rng(seed)
    t_lo, t_hi = _log10_bounds(bounds)
    trace = []
    for t in np.linspace(t_lo, t_hi, n_init):
        a = float(10.0 ** t)
        trace.append((a, objective(a)))
    X = np.array([[math.log10(a)] for a, _ in trace])
    y = np.array([s for _, s in trace])
    kernel = (ConstantKernel(1.0, (1e-3, 1e3))
              * Matern(length_scale=1.0, length_scale_bounds=(1e-2, 1e2), nu=2.5)
              + WhiteKernel(noise_level=1e-3, noise_level_bounds=(1e-5, 1e-1)))
    grid = np.linspace(t_lo, t_hi, 500).reshape(-1, 1)
    for _ in range(n_iter):
        try:
            gp = GaussianProcessRegressor(kernel=kernel, normalize_y=True,
                                            n_restarts_optimizer=2,
                                            random_state=seed).fit(X, y)
            ei = _gp_ei(gp, grid, y.max())
            t_next = float(grid[int(np.argmax(ei))][0])
        except Exception:
            t_next = float(rng.uniform(t_lo, t_hi))
        if any(abs(t_next - math.log10(a)) < 1e-3 for a, _ in trace):
            t_next = float(rng.uniform(t_lo, t_hi))
        a_next = float(10.0 ** t_next)
        s = objective(a_next)
        trace.append((a_next, s))
        X = np.vstack([X, [[t_next]]])
        y = np.append(y, s)
    best = max(trace, key=lambda x: x[1])
    return best[0], best[1], trace


SEARCH_FUNCS = {
    "grid":            lambda obj, b: search_grid(obj, bounds=b, n=15),
    "golden_section":  lambda obj, b: search_golden(obj, bounds=b, max_iter=12),
    "bayesian":        lambda obj, b: search_bayesian(obj, bounds=b, n_init=5, n_iter=10),
}


# ============================================================ #
# Public entry                                                   #
# ============================================================ #
def run_autotune(
    adata: AnnData,
    output_dir: str,
    *,
    sample_col: str = "sample",
    celltype_col: str = "cell_type",
    comp_emb_key: Optional[str] = None,
    rmd_emb_key: Optional[str] = None,
    modality_col: Optional[str] = None,
    batch_col: Optional[Union[str, List[str]]] = None,
    grouping_col: Optional[str] = None,
    medium_K: int = 120,
    fine_K: int = 300,
    rmd_dim: int = 8,
    pca_components: int = 10,
    batch_method: str = "harmony",
    scoring: str = "auto",
    search: str = "bayesian",
    scope: str = "alpha_only",
    alpha_bounds: Tuple[float, float] = DEFAULT_ALPHA_BOUNDS,
    seed: int = 42,
    save: bool = True,
    verbose: bool = True,
    tune_on_modality: Optional[str] = None,
    cluster_emb_key: Optional[str] = None,
    save_cell_adata: bool = True,
) -> Dict:
    """Run autotune and return the best params + final sample-AnnData.

    ``tune_on_modality`` (e.g. ``"RNA"``) restricts BOTH the bio-preservation
    and batch-correction proxies to units of that modality during the search,
    while the final embedding is still built on ALL units. Use this to ask:
    "what α best tunes the joint embedding for one modality's labels — and
    how does the other modality fare under that α?". Set to ``None`` (default)
    to score on every unit (current behaviour).
    """
    if cluster_emb_key is not None:
        warnings.warn("cluster_emb_key= is deprecated and will be removed in 1.0; "
                      "use comp_emb_key=.", FutureWarning, stacklevel=2)
        if comp_emb_key is None:
            comp_emb_key = cluster_emb_key

    t0 = time.time()
    primary_batch = batch_col[0] if isinstance(batch_col, (list, tuple)) and batch_col else batch_col
    if isinstance(primary_batch, list):
        primary_batch = primary_batch[0] if primary_batch else None

    blocks = build_blocks(
        adata, sample_col=sample_col, celltype_col=celltype_col,
        comp_emb_key=comp_emb_key, rmd_emb_key=rmd_emb_key,
        modality_col=modality_col, batch_col=primary_batch,
        grouping_col=grouping_col, medium_K=medium_K, fine_K=fine_K,
        rmd_dim=rmd_dim, seed=seed, verbose=verbose,
    )

    # Scoring mask: when tune_on_modality is set, restrict scoring proxies
    # to that modality's units (the final embedding is still built on all).
    score_mask = np.ones(blocks["n_units"], dtype=bool)
    score_meta = blocks
    if tune_on_modality is not None:
        score_mask = np.asarray(blocks["unit_groups"]) == tune_on_modality
        if score_mask.sum() < 5:
            raise ValueError(
                f"tune_on_modality={tune_on_modality!r} leaves only "
                f"{int(score_mask.sum())} units — too few to score on.")
        # Only `grouping`, `batch`, and the has_* flags are read by make_scorer.
        score_meta = dict(blocks)
        for key in ("grouping", "batch"):
            v = blocks.get(key)
            if v is not None and len(v) == len(score_mask):
                score_meta[key] = np.asarray(v)[score_mask]
        score_meta["has_batch"] = (score_meta.get("batch") is not None and
                                    len(set(np.asarray(score_meta["batch"]).tolist())) > 1)
        score_meta["has_grouping"] = (score_meta.get("grouping") is not None and
                                       len({x for x in score_meta["grouping"] if pd.notna(x)}) > 1)
        if verbose:
            print(f"[autotune] tune_on_modality={tune_on_modality!r}: "
                  f"scoring on {int(score_mask.sum())}/{blocks['n_units']} units")

    if not score_meta["has_batch"] and not score_meta["has_grouping"]:
        alpha = resolve_rmd_weight("equal", blocks["K_c"], blocks["K_med"], blocks["K_fine"])
        if verbose:
            print(f"[autotune] no batch and no grouping column → using the default "
                  f"rmd_weight='equal' (α={alpha}); no search performed.")
        weights = derive_weights(blocks["K_c"], blocks["K_med"], blocks["K_fine"],
                                   rmd_weight=alpha, n_blocks=4)
        final_emb = build_emb_from_blocks(
            [blocks["A1"], blocks["A2"], blocks["A3"], blocks["RMD"]],
            weights,
            unit_ids=blocks["unit_ids"],
            unit_groups=blocks["unit_groups"],
            unit_batches=blocks["unit_batches"],
            pca_components=pca_components, batch_method=batch_method,
            seed=seed, verbose=verbose,
        )
        return _finalize(adata, blocks, final_emb, weights,
                         best_params={"rmd_weight": alpha},
                         best_score=float("nan"),
                         trace=[], search=search, scoring=scoring,
                         scope=scope, alpha_bounds=alpha_bounds,
                         pca_components=pca_components,
                         batch_method=batch_method,
                         output_dir=output_dir, save=save, save_cell_adata=save_cell_adata,
                         t_start=t0, verbose=verbose,
                         tune_on_modality=tune_on_modality,
                         score_n_units=int(score_mask.sum()))

    if scope != "alpha_only":
        raise ValueError(
            f"only scope='alpha_only' is supported in this generalized port "
            f"(got '{scope}')")

    score_fn = make_scorer(scoring, score_meta)

    def objective(alpha: float) -> float:
        weights = derive_weights(blocks["K_c"], blocks["K_med"], blocks["K_fine"],
                                   rmd_weight=alpha, n_blocks=4)
        emb_df = build_emb_from_blocks(
            [blocks["A1"], blocks["A2"], blocks["A3"], blocks["RMD"]],
            weights,
            unit_ids=blocks["unit_ids"],
            unit_groups=blocks["unit_groups"],
            unit_batches=blocks["unit_batches"],
            pca_components=pca_components, batch_method=batch_method,
            seed=seed, verbose=False,
        )
        emb_arr = emb_df.values[score_mask] if not score_mask.all() else emb_df.values
        return float(score_fn(emb_arr))

    if search not in SEARCH_FUNCS:
        raise ValueError(f"unknown search '{search}' (choices: {list(SEARCH_FUNCS)})")
    if verbose:
        print(f"[autotune] search={search}  scoring={scoring}  "
              f"scope={scope}  bounds={alpha_bounds}")
    best_alpha, best_score, trace = SEARCH_FUNCS[search](objective, alpha_bounds)
    if verbose:
        print(f"[autotune] best rmd_weight={best_alpha:.4f}  score={best_score:.4f}  "
              f"({len(trace)} evals)")

    final_weights = derive_weights(blocks["K_c"], blocks["K_med"], blocks["K_fine"],
                                     rmd_weight=best_alpha, n_blocks=4)
    final_emb = build_emb_from_blocks(
        [blocks["A1"], blocks["A2"], blocks["A3"], blocks["RMD"]],
        final_weights,
        unit_ids=blocks["unit_ids"],
        unit_groups=blocks["unit_groups"],
        unit_batches=blocks["unit_batches"],
        pca_components=pca_components, batch_method=batch_method,
        seed=seed, verbose=verbose,
    )

    return _finalize(adata, blocks, final_emb, final_weights,
                     best_params={"rmd_weight": float(best_alpha)},
                     best_score=float(best_score),
                     trace=trace, search=search, scoring=scoring,
                     scope=scope, alpha_bounds=alpha_bounds,
                     pca_components=pca_components,
                     batch_method=batch_method,
                     output_dir=output_dir, save=save, save_cell_adata=save_cell_adata,
                     t_start=t0, verbose=verbose,
                     tune_on_modality=tune_on_modality,
                     score_n_units=int(score_mask.sum()))


# Proxy-component descriptions for the human-readable report.
_PROXY_DESCRIPTIONS = {
    "cca":             ("supervised", "CCA(emb, grouping_col) — canonical correlation between embedding and grouping label"),
    "sps":             ("supervised", "SPS(emb, grouping_col) — between/within-quartile distance ratio"),
    "cv_knn_severity": ("supervised", "CV-kNN — 5-fold cross-validated MAE of k=3 kNN regression on grouping"),
    "pseudotime_spearman": ("supervised", "|Spearman(PC1, grouping)| — pseudotime alignment"),
    "ilisi_batch":     ("unsupervised", "iLISI(emb, batch) — k-NN batch mixing"),
    "neg_asw_batch":   ("unsupervised", "−ASW(emb, batch) — negative silhouette of batch labels"),
}


def _active_proxies(scoring: str, has_batch: bool, has_grouping: bool):
    """Return the list of proxy names the scorer actually evaluates."""
    if scoring in ("auto", "multi_metric_proxy", "ilisi_label"):
        two_term = scoring == "ilisi_label"
        names = []
        if has_grouping:
            names += ["cca"] if two_term else ["cca", "sps"]
        if has_batch:
            names += ["ilisi_batch"] if two_term else ["ilisi_batch", "neg_asw_batch"]
        return names
    return [scoring] if scoring in _PROXY_DESCRIPTIONS else [scoring]


def _format_autotune_report(*, best_params, best_score, trace, weights,
                              blocks, search, scoring, scope, alpha_bounds,
                              pca_components, batch_method, elapsed_s,
                              tune_on_modality=None, score_n_units=None):
    """Build the human-readable autotune_record.txt content."""
    has_batch = bool(blocks.get("has_batch"))
    has_grouping = bool(blocks.get("has_grouping"))
    n_units = int(blocks.get("n_units", 0))
    n_groups = len(set(blocks.get("unit_groups") or []))
    proxies = _active_proxies(scoring, has_batch, has_grouping)

    lines = []
    lines.append("Sample-embedding autotune — composition + RMD")
    lines.append("=" * 68)
    lines.append("")
    lines.append("Configuration")
    lines.append("-" * 68)
    lines.append(f"  search algorithm   : {search}")
    lines.append(f"  scoring strategy   : {scoring}")
    lines.append(f"  scope              : {scope}")
    lines.append(f"  α bounds           : [{alpha_bounds[0]:g}, {alpha_bounds[1]:g}]")
    lines.append(f"  PCA components     : {pca_components}")
    lines.append(f"  sample Harmony     : {batch_method}")
    lines.append(f"  number of units    : {n_units}")
    lines.append(f"  unique groups      : {n_groups}")
    lines.append(f"  has batch column   : {has_batch}")
    lines.append(f"  has grouping col   : {has_grouping}")
    if tune_on_modality is not None:
        lines.append(f"  tune_on_modality   : {tune_on_modality}  "
                      f"(scoring on {score_n_units if score_n_units is not None else '?'}/{n_units} units; "
                      "final embedding still on all units)")
    lines.append("")
    lines.append("Block setup (inverse-variance weights from K values)")
    lines.append("-" * 68)
    lines.append(f"  K_c   (cell types) : {int(blocks['K_c'])}")
    lines.append(f"  K_med (k-means)    : {int(blocks['K_med'])}")
    lines.append(f"  K_fine (k-means)   : {int(blocks['K_fine'])}")
    lines.append(f"  comp_emb_key       : {blocks.get('comp_emb_key', '?')}")
    lines.append(f"  rmd_emb_key        : {blocks.get('rmd_emb_key', '?')}")
    lines.append("")
    lines.append("Active scoring proxies (gated by data availability)")
    lines.append("-" * 68)
    if not proxies:
        lines.append("  (none — no batch or grouping column available; defaults used)")
    else:
        for name in proxies:
            kind, desc = _PROXY_DESCRIPTIONS.get(name, ("?", name))
            lines.append(f"  - [{kind:<12s}] {name:<20s}  {desc}")
        if scoring in ("auto", "multi_metric_proxy", "ilisi_label"):
            lines.append(f"  ensemble: {scoring} = mean of the proxies above (each min-max scaled).")
    lines.append("")
    lines.append("Result")
    lines.append("-" * 68)
    for k, v in best_params.items():
        if isinstance(v, float):
            lines.append(f"  best {k:<14s}: {v:.6f}")
        else:
            lines.append(f"  best {k:<14s}: {v}")
    lines.append(f"  best score        : {best_score:.6f}")
    lines.append(f"  block weights     : "
                  + ", ".join(f"{x:.4f}" for x in weights)
                  + "  (A1, A2, A3, RMD)")
    lines.append(f"  total evaluations : {len(trace)}")
    lines.append(f"  wall time         : {elapsed_s:.2f} s")
    # A flat objective makes the single winning α arbitrary within the plateau;
    # report the plateau so the number is not read as more precise than it is.
    near = [a for a, s in trace
            if best_score == best_score and s >= best_score - 0.01 * abs(best_score)]
    if len(near) > 1:
        lines.append(f"  α within 1% of best: [{min(near):g}, {max(near):g}]  "
                     f"({len(near)}/{len(trace)} evaluations) — the objective is "
                     f"flat over this range")
    alpha_best = best_params.get("rmd_weight")
    if alpha_best is not None and any(
            abs(alpha_best - b) <= 1e-9 * max(1.0, abs(b)) for b in alpha_bounds):
        lines.append(f"  NOTE: α equals a search bound; the optimum may lie outside "
                     f"[{alpha_bounds[0]:g}, {alpha_bounds[1]:g}] — widen "
                     f"alpha_bounds and re-run.")
    lines.append("")
    lines.append(f"Search trace ({len(trace)} evals, top 25 by score)")
    lines.append("-" * 68)
    lines.append(f"  {'rank':>4s}  {'α (rmd_weight)':>16s}  {'score':>10s}")
    sorted_trace = sorted(trace, key=lambda r: r[1], reverse=True)
    for i, (a, s) in enumerate(sorted_trace[:25], 1):
        marker = "  ★ best" if i == 1 else ""
        lines.append(f"  {i:>4d}  {a:>16.6f}  {s:>10.4f}{marker}")
    if len(sorted_trace) > 25:
        lines.append(f"  ... ({len(sorted_trace) - 25} more)")
    lines.append("")
    lines.append(f"Full chronological trace ({len(trace)} evals)")
    lines.append("-" * 68)
    lines.append(f"  {'step':>4s}  {'α (rmd_weight)':>16s}  {'score':>10s}")
    for i, (a, s) in enumerate(trace, 1):
        lines.append(f"  {i:>4d}  {a:>16.6f}  {s:>10.4f}")
    lines.append("")
    return "\n".join(lines)


def _finalize(adata, blocks, final_emb, weights, *,
               best_params, best_score, trace,
               search, scoring, scope, alpha_bounds,
               pca_components, batch_method,
               output_dir, save, t_start, verbose,
               tune_on_modality=None, score_n_units=None, save_cell_adata=True):
    """Write the autotuned embedding into the cell-level adata and persist artifacts."""
    elapsed = time.time() - t_start
    adata.uns["X_DR_sample"] = final_emb.copy()
    adata.uns["sample_embedding_params"] = {
        "best_params": best_params,
        "best_score": best_score,
        "search": search,
        "scoring": scoring,
        "scope": scope,
        "block_weights": list(map(float, weights)),
        "K_c": int(blocks["K_c"]),
        "K_med": int(blocks["K_med"]),
        "K_fine": int(blocks["K_fine"]),
        "comp_emb_key": str(blocks.get("comp_emb_key", "")),
        # Deprecated 0.2.0 spelling; removed in 1.0.
        "cluster_emb_key": str(blocks.get("comp_emb_key", "")),
        "rmd_emb_key": str(blocks.get("rmd_emb_key", "")),
        "n_evals": len(trace),
        "autotuned": True,
        "wall_time_s": float(elapsed),
    }

    if save:
        # When tuning on a single modality, write to a sibling subdir so the
        # default sample_embedding.csv from a prior all-modality run isn't
        # overwritten (e.g. sample_embedding_tune-on-RNA/).
        subdir = "sample_embedding"
        if tune_on_modality is not None:
            subdir = f"sample_embedding_tune-on-{tune_on_modality}"
        out_dir = os.path.join(output_dir, subdir)
        os.makedirs(out_dir, exist_ok=True)
        emb_csv = os.path.join(out_dir, "sample_embedding.csv")
        final_emb.to_csv(emb_csv)

        preprocessed_h5 = os.path.join(output_dir, "preprocess", "adata_preprocessed.h5ad")
        if not save_cell_adata:
            warn_if_stale_embedding(preprocessed_h5, emb_csv)
        if save_cell_adata and os.path.exists(preprocessed_h5):
            try:
                save_embedding_to_h5ad(preprocessed_h5, adata)
            except Exception as exc:
                if verbose:
                    print(f"[autotune] WARNING: could not re-save "
                          f"{preprocessed_h5}: {exc}")

        report = _format_autotune_report(
            best_params=best_params, best_score=best_score, trace=trace,
            weights=weights, blocks=blocks, search=search, scoring=scoring,
            scope=scope, alpha_bounds=alpha_bounds,
            pca_components=pca_components, batch_method=batch_method,
            elapsed_s=elapsed,
            tune_on_modality=tune_on_modality, score_n_units=score_n_units,
        )
        report_path = os.path.join(out_dir, "autotune_record.txt")
        with open(report_path, "w", encoding="utf-8") as f:
            f.write(report)
        if verbose:
            print(f"[autotune] wrote {emb_csv}")
            print(f"[autotune] wrote {report_path}")

    if verbose:
        print(f"[autotune] done in {elapsed:.2f}s")

    return {
        "best_params": best_params,
        "best_score": best_score,
        "trace": trace,
        "block_weights": list(map(float, weights)),
        "adata": adata,
        "sample_embedding": final_emb,
    }

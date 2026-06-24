#!/usr/bin/env python3
"""
material_models.py — φ→E 材料マッピングの集約モジュール
=======================================================

DI ベース (Shannon entropy) と φ_Pg ベース (病原菌濃度) の
2つの E(x) マッピングを提供する。

DI モデル (既存)
----------------
  r = clamp(DI / s_DI, 0, 1)
  E = E_max * (1 - r)^n + E_min * r
  問題: So支配 と Pg支配 を区別できない (entropy のみ)

φ_Pg モデル (新規, メカニズムベース)
------------------------------------
  Pg が gingipain (プロテアーゼ) を分泌 → コラーゲン分解 → 剛性低下
  E = E_healthy - (E_healthy - E_degraded) * σ(φ_Pg / φ_crit)
  σ = Hill sigmoid: x^m / (1 + x^m)

  物理的根拠:
  - Pg の LPS・gingipain は濃度依存的に組織破壊
  - 閾値 φ_crit 以下では組織は健全
  - Hill 係数 m で遷移の急峻さを制御

Virulence index モデル (拡張)
-----------------------------
  V(x) = w_Pg * φ_Pg + w_Fn * φ_Fn
  Fn も LPS・外膜小胞で炎症促進 → 重み付き和
  E(V) = E_healthy - ΔE * σ(V / V_crit)

追加モデル (学術的妥当性順)
---------------------------
  1. Simpson DI: Simpson index D = 1 - Σp_i² → DI_simpson = D (dominance-sensitive)
  2. Voigt mixing: E = Σ φ_i E_i (rule of mixtures, variational-compatible)
  3. Gini evenness: Gini coefficient → 1-Gini as dysbiosis proxy
  4. Pielou evenness: J = H/ln(S) → 1-J as dysbiosis proxy
  5. Reuss mixing: 1/E = Σ φ_i/E_i (inverse rule)

使い方
------
  from material_models import (
      compute_E_di, compute_E_phi_pg, compute_E_virulence,
      compute_di_simpson, compute_E_voigt, compute_E_reuss,
      compute_di_gini, compute_di_pielou,
  )

環境: numpy / jax 両対応 (jax はオプショナル)
"""

from __future__ import annotations
import numpy as np

# ── デフォルトパラメータ ──────────────────────────────────────────────────────

# 共通
E_MAX_PA = 1000.0  # E_healthy [Pa] (commensal upper limit)
E_MIN_PA = 10.0  # E_degraded [Pa] (dysbiotic lower limit)

# DI モデル
DI_SCALE = 1.0   # Shannon DI ∈ [0,1]: 直接使用 (旧値 0.025778 は DI を過小評価していた)
DI_EXPONENT = 2.0  # 冪乗則指数

# φ_Pg モデル
# 0D Hamilton ODE: commensal φ_Pg ≈ 0.167 (均等), dysbiotic φ_Pg ≈ 0.8 (Pg支配)
# φ_crit は σ(0.167/φ_crit) ≈ 0 (健全) かつ σ(0.8/φ_crit) ≈ 1 (分解) を満たす値
PHI_PG_CRIT = 0.25  # Pg vol.fraction 閾値 (calibrated for 0D ODE output)
HILL_M = 4.0  # Hill 係数 (遷移の急峻さ, m=1: Michaelis, m→∞: step)

# Virulence index モデル
W_PG = 1.0  # Pg 重み
W_FN = 0.3  # Fn 重み (Pg より弱い病原性)
V_CRIT = 0.30  # Virulence 閾値 (calibrated for 0D ODE output)

# Species index (Hamilton ODE order)
IDX_PG = 4  # P. gingivalis = species[4]
IDX_FN = 3  # F. nucleatum  = species[3]

# Voigt/Reuss mixing: species-specific elastic moduli [Pa]
# Ref: Pattem 2018 (oral biofilm 0.55-14 kPa), Ehret 2013 (network), Laspidou 2014
# Pg weakest (gingipain), So/An stronger (EPS producers)
E_SPECIES_PA = np.array([1000.0, 800.0, 600.0, 200.0, 10.0])  # So, An, Vei, Fn, Pg

# EPS synergy model: species-specific EPS production rates
# Ref: Fujiwara 2000 (So gtfR, soluble glucan), Koo 2013 (insoluble glucan scaffold),
#      Gloag 2019 (dual-species emergent properties), Simoes 2009 (multi-species synergy)
# εᵢ > 0: EPS production (contributes to matrix)
# εᵢ < 0: matrix degradation (net negative, e.g. gingipain protease)
EPS_RATES = np.array([0.3, 0.6, 0.1, 0.4, -0.3])  # So, An, Vei, Fn, Pg
EPS_GAMMA = 4.0  # Cross-linking synergy strength (calibrated to Pattem 10-80× range)

# Mechanistic composite model (hydrogel scaling)
# Species-specific STRUCTURAL EPS production rates rᵢ (normalized, 0-1)
# Only matrix-contributing EPS counted; Pg capsule is cell-associated, not structural
# Ref: Fujiwara 2000 (So gtfR glucan), Koo 2013 (insoluble glucan scaffold),
#      Kolenbrander 2010, Fong & Yildiz 2015 (VPS not relevant for oral)
MECH_EPS_RATES = np.array([1.0, 0.6, 0.05, 0.15, 0.0])  # So, An, Vd, Fn, Pg
# α calibrated from actual ODE posterior outputs:
# quality(CS)/quality(DH) ≈ 1.76, E(CS)/E(DH) ≈ 3.21
# → α = ln(3.21)/ln(1.76) ≈ 2.07 (consistent with de Gennes 2.0-2.5 for hydrogels)
MECH_ALPHA = 2.07  # hydrogel scaling exponent (calibrated to CS-DH range, cf. de Gennes)
MECH_E0 = 221340.0  # reference modulus [Pa] (at quality=1, calibrated for CS≈900 Pa)
MECH_E_CELL = 500.0  # cell modulus [Pa] (Luo 2012, AFM: 100-1000 Pa)
MECH_PHI_CELL = 0.15  # cell volume fraction (Flemming 2010: 10-25% cells in biofilm)


# ─────────────────────────────────────────────────────────────────────────────
# NumPy implementations
# ─────────────────────────────────────────────────────────────────────────────


def compute_E_di(
    di: np.ndarray,
    e_max: float = E_MAX_PA,
    e_min: float = E_MIN_PA,
    di_scale: float = DI_SCALE,
    exponent: float = DI_EXPONENT,
) -> np.ndarray:
    """
    DI → E(DI) 冪乗則 (既存モデル).

    E = E_max * (1-r)^n + E_min * r,  r = clamp(DI/s, 0, 1)
    """
    r = np.clip(di / di_scale, 0.0, 1.0)
    return e_max * (1.0 - r) ** exponent + e_min * r


def _hill_sigmoid(x: np.ndarray, m: float) -> np.ndarray:
    """Hill sigmoid: x^m / (1 + x^m), 0→0, 1→0.5, ∞→1."""
    xm = np.power(np.clip(x, 0.0, None), m)
    return xm / (1.0 + xm)


def compute_E_phi_pg(
    phi_species: np.ndarray,
    e_max: float = E_MAX_PA,
    e_min: float = E_MIN_PA,
    phi_crit: float = PHI_PG_CRIT,
    hill_m: float = HILL_M,
) -> np.ndarray:
    """
    φ_Pg → E(φ_Pg) Hill sigmoid (メカニズムベース).

    E = E_max - (E_max - E_min) * σ(φ_Pg / φ_crit)
    σ(x) = x^m / (1 + x^m)

    Parameters
    ----------
    phi_species : (..., 5) array — 菌種別 volume fraction
    phi_crit    : float — Pg 閾値 (default 0.05)
    hill_m      : float — Hill 係数 (default 4.0)

    Returns
    -------
    E : (...) array — 局所剛性 [Pa]

    物理的意味:
    - φ_Pg < φ_crit: E ≈ E_max (組織健全)
    - φ_Pg > φ_crit: E → E_min (組織破壊)
    - m が大きいほど遷移が急峻
    """
    phi_pg = np.asarray(phi_species)[..., IDX_PG]
    sig = _hill_sigmoid(phi_pg / phi_crit, hill_m)
    return e_max - (e_max - e_min) * sig


def compute_E_virulence(
    phi_species: np.ndarray,
    e_max: float = E_MAX_PA,
    e_min: float = E_MIN_PA,
    w_pg: float = W_PG,
    w_fn: float = W_FN,
    v_crit: float = V_CRIT,
    hill_m: float = HILL_M,
) -> np.ndarray:
    """
    Virulence index V → E(V) (Pg + Fn 重み付き).

    V(x) = w_Pg * φ_Pg(x) + w_Fn * φ_Fn(x)
    E(V) = E_max - (E_max - E_min) * σ(V / V_crit)

    根拠: Fn は Pg の co-aggregation partner であり、
    外膜小胞 (OMV) + LPS を通じた炎症促進作用を持つ。
    """
    phi = np.asarray(phi_species)
    v = w_pg * phi[..., IDX_PG] + w_fn * phi[..., IDX_FN]
    sig = _hill_sigmoid(v / v_crit, hill_m)
    return e_max - (e_max - e_min) * sig


def compute_di(phi_species: np.ndarray) -> np.ndarray:
    """DI = 1 - H/H_max (Shannon entropy ベース)."""
    phi_sum = np.asarray(phi_species).sum(axis=-1, keepdims=True)
    phi_sum = np.where(phi_sum > 0, phi_sum, 1.0)
    p = np.asarray(phi_species) / phi_sum
    with np.errstate(divide="ignore", invalid="ignore"):
        log_p = np.where(p > 0, np.log(p), 0.0)
    H = -(p * log_p).sum(axis=-1)
    return 1.0 - H / np.log(5.0)


def compute_di_simpson(phi_species: np.ndarray) -> np.ndarray:
    """
    Simpson-based dysbiosis index.

    Simpson index D = 1 - Σ p_i² (probability of interspecific encounter).
    D_max = 1 - 1/S for uniform (S species). Normalize: DI = 1 - D/D_max
    so that DI=0 for uniform (commensal), DI=1 for single-species (dysbiotic).
    """
    phi_sum = np.asarray(phi_species).sum(axis=-1, keepdims=True)
    phi_sum = np.where(phi_sum > 0, phi_sum, 1.0)
    p = np.asarray(phi_species) / phi_sum
    n = p.shape[-1]
    D = 1.0 - (p * p).sum(axis=-1)  # Simpson diversity
    D_max = 1.0 - 1.0 / n  # max for uniform
    return 1.0 - D / (D_max + 1e-12)  # DI: 0=commensal, 1=dysbiotic


def compute_di_gini(phi_species: np.ndarray) -> np.ndarray:
    """
    Gini-based dysbiosis index.

    Gini coefficient: 0=perfect equality, 1=complete inequality.
    Sort p, compute 2*Σ(i*p_i) - (n+1)/n. DI_gini = Gini (high=unequal=dysbiotic).
    """
    phi_sum = np.asarray(phi_species).sum(axis=-1, keepdims=True)
    phi_sum = np.where(phi_sum > 0, phi_sum, 1.0)
    p = np.asarray(phi_species) / phi_sum
    n = p.shape[-1]
    # Sort each row
    p_sorted = np.sort(p, axis=-1)
    # Gini = (2 * sum(i * x_i) - (n+1)) / n  for sorted x
    idx = np.arange(1, n + 1, dtype=np.float64)
    gini = (2.0 * (p_sorted * idx).sum(axis=-1) - (n + 1)) / n
    return np.clip(gini, 0.0, 1.0)


def compute_di_pielou(phi_species: np.ndarray) -> np.ndarray:
    """
    Pielou evenness-based dysbiosis index.

    J = H / ln(S), S=species count. J=1: perfectly even, J=0: maximally uneven.
    DI_pielou = 1 - J (high=uneven=dysbiotic).
    """
    phi_sum = np.asarray(phi_species).sum(axis=-1, keepdims=True)
    phi_sum = np.where(phi_sum > 0, phi_sum, 1.0)
    p = np.asarray(phi_species) / phi_sum
    with np.errstate(divide="ignore", invalid="ignore"):
        log_p = np.where(p > 0, np.log(p), 0.0)
    H = -(p * log_p).sum(axis=-1)
    S = 5.0  # fixed species count
    J = H / (np.log(S) + 1e-12)
    return 1.0 - np.clip(J, 0.0, 1.0)


def compute_E_eps_synergy(
    phi_species: np.ndarray,
    eps_rates: np.ndarray | None = None,
    gamma: float = EPS_GAMMA,
    e_max: float = E_MAX_PA,
    e_min: float = E_MIN_PA,
) -> np.ndarray:
    """
    EPS synergy model: E from species-specific EPS production + cross-linking.

    Two factors determine biofilm stiffness:
      1. Total EPS production (species-specific rates εᵢ)
      2. Cross-linking synergy (multiple EPS types form stronger network)

    E(φ) = E_min + (E_max - E_min) × M(φ) / M_ref

    where M(φ) = EPS_total × exp(γ × CrossLink)
          EPS_total = max(Σ φᵢ εᵢ, 0)
          CrossLink = H(φ_active) / H_max  (Shannon evenness of EPS producers)

    Ref: Pattem 2018 (EPS:cell ratio → E), Gloag 2019 (emergent dual-species),
         Simoes 2009 (multi-species synergy), Fujiwara 2000 (So gtfR)
    """
    phi = np.asarray(phi_species)
    eps = eps_rates if eps_rates is not None else EPS_RATES

    # Normalize fractions
    phi_sum = phi.sum(axis=-1, keepdims=True)
    phi_sum = np.where(phi_sum > 0, phi_sum, 1.0)
    p = phi / phi_sum

    # 1. Total EPS production index
    eps_total = np.clip((p * eps).sum(axis=-1), 0.0, None)

    # 2. Cross-linking: Shannon evenness of EPS-producing species only
    active_mask = eps > 0  # boolean mask for producers
    p_active = p[..., active_mask]
    p_active_sum = p_active.sum(axis=-1, keepdims=True)
    p_active_sum = np.where(p_active_sum > 0, p_active_sum, 1.0)
    p_norm = p_active / p_active_sum
    with np.errstate(divide="ignore", invalid="ignore"):
        log_p = np.where(p_norm > 1e-12, np.log(p_norm), 0.0)
    H = -(p_norm * log_p).sum(axis=-1)
    H_max = np.log(float(active_mask.sum()))
    cross_link = H / H_max if H_max > 0 else np.zeros_like(H)

    # 3. Matrix quality
    M = eps_total * np.exp(gamma * cross_link)

    # Reference M for normalization (theoretical max: uniform EPS producers)
    n_active = int(active_mask.sum())
    eps_active = eps[active_mask]
    eps_total_ref = float(np.mean(eps_active))  # uniform active species
    M_ref = eps_total_ref * np.exp(gamma * 1.0) * 1.1  # H/H_max=1, +10% headroom

    # 4. Map to E range
    return e_min + (e_max - e_min) * np.clip(M / M_ref, 0.0, 1.0)


def compute_E_composite(
    phi_species: np.ndarray,
    eps_rates: np.ndarray | None = None,
    alpha: float = MECH_ALPHA,
    e0: float = MECH_E0,
    e_cell: float = MECH_E_CELL,
    phi_cell: float = MECH_PHI_CELL,
) -> np.ndarray:
    """
    Mechanistic composite model: φᵢ → φ_EPS × CrossLink → hydrogel E.

    Derivation chain (each step has theoretical basis):
      1. φ_EPS = Σ rᵢ φᵢ / Σ rᵢ   (linear mixing of EPS production rates)
      2. CrossLink = exp(H') where H' = Shannon entropy of EPS-weighted composition
         (Kantor & Webman 1984: diverse cross-link types → higher network rigidity;
          Rubinstein & Colby 2003: interpenetrating networks scale super-linearly)
      3. E_matrix = E₀ × (φ_EPS × CrossLink)^α   (hydrogel + diversity scaling)
      4. E_eff = Mori-Tanaka(E_matrix, E_cell, φ_cell)

    The key mechanistic insight: φ_EPS alone is insufficient because a monoculture
    biofilm with high EPS still has a single cross-link type (weak network).
    Multiple EPS types (glucan + heteropolysaccharide + eDNA + protein) create
    an interpenetrating network that is stronger than any single-polymer gel.

    Parameters:
      eps_rates: species-specific EPS production rates rᵢ [So, An, Vd, Fn, Pg]
      alpha: hydrogel scaling exponent (calibrated to Pattem 2018)
      e0: reference modulus [Pa]
      e_cell: cell elastic modulus [Pa]
      phi_cell: cell volume fraction in biofilm

    Ref: Flory 1953, de Gennes 1979, Oyen 2014, Kantor & Webman 1984,
         Rubinstein & Colby 2003, Mori-Tanaka 1973, Milton 2002
    """
    phi = np.asarray(phi_species)
    r = eps_rates if eps_rates is not None else MECH_EPS_RATES

    # Normalize fractions
    phi_sum = phi.sum(axis=-1, keepdims=True)
    phi_sum = np.where(phi_sum > 0, phi_sum, 1.0)
    p = phi / phi_sum

    # 1. EPS volume fraction (normalized by max possible)
    r_sum = r.sum()
    phi_eps = np.clip((p * r).sum(axis=-1) / (r_sum + 1e-12), 0.0, 1.0)

    # 2. Cross-linking diversity: Shannon evenness of EPS-producing species
    # Weight species by EPS contribution: w_i = r_i * phi_i
    eps_contrib = p * r  # (n, 5) per-species EPS contribution
    eps_total = eps_contrib.sum(axis=-1, keepdims=True)
    eps_total = np.where(eps_total > 1e-12, eps_total, 1.0)
    q = eps_contrib / eps_total  # fractional EPS contribution per species

    with np.errstate(divide="ignore", invalid="ignore"):
        log_q = np.where(q > 1e-12, np.log(q), 0.0)
    H = -(q * log_q).sum(axis=-1)  # Shannon entropy of EPS composition
    # Effective number of EPS types: exp(H), max = N_producers
    n_eff = np.exp(H)  # 1 (monoculture) to N (uniform)
    n_max = float((r > 0).sum())  # max possible (species with r > 0)
    cross_link = n_eff / n_max  # normalized to [0, 1]

    # 3. Combined EPS quality index: amount × diversity
    # Physical interpretation: total cross-link density ∝ φ_EPS × diversity
    quality = phi_eps * cross_link

    # 4. Hydrogel matrix modulus (power-law scaling)
    E_matrix = e0 * np.power(np.clip(quality, 1e-8, None), alpha)

    # 5. Mori-Tanaka dilute inclusion correction
    nu_m = 0.45
    contrast = np.where(E_matrix > 1e-6, 1.0 - e_cell / E_matrix, 0.0)
    concentration_factor = 3.0 / (2.0 + nu_m)
    E_eff = E_matrix * (1.0 - phi_cell * contrast * concentration_factor)

    # Clamp to physical range
    return np.clip(E_eff, E_MIN_PA, E_MAX_PA)


def compute_E_voigt(
    phi_species: np.ndarray,
    e_species: np.ndarray | None = None,
) -> np.ndarray:
    """
    Voigt (rule of mixtures): E = Σ φ_i E_i.

    Variational-compatible: E is linear in φ. Upper bound for composite modulus.
    Ref: Rule of mixtures, effective medium theory.
    """
    phi_sum = np.asarray(phi_species).sum(axis=-1, keepdims=True)
    phi_sum = np.where(phi_sum > 0, phi_sum, 1.0)
    p = np.asarray(phi_species) / phi_sum
    E_i = e_species if e_species is not None else E_SPECIES_PA
    return (p * E_i).sum(axis=-1)


def compute_E_reuss(
    phi_species: np.ndarray,
    e_species: np.ndarray | None = None,
) -> np.ndarray:
    """
    Reuss (inverse rule): 1/E = Σ φ_i/E_i.

    Lower bound for composite modulus. Series loading analogy.
    """
    phi_sum = np.asarray(phi_species).sum(axis=-1, keepdims=True)
    phi_sum = np.where(phi_sum > 0, phi_sum, 1.0)
    p = np.asarray(phi_species) / phi_sum
    E_i = e_species if e_species is not None else E_SPECIES_PA
    inv_E = (p / (E_i + 1e-12)).sum(axis=-1)
    return 1.0 / (inv_E + 1e-12)


def compute_E_di_simpson(
    phi_species: np.ndarray,
    e_max: float = E_MAX_PA,
    e_min: float = E_MIN_PA,
    di_scale: float = 1.0,
    exponent: float = DI_EXPONENT,
) -> np.ndarray:
    """E from Simpson-based DI (same power-law as Shannon DI)."""
    di = compute_di_simpson(phi_species)
    return compute_E_di(di, e_max, e_min, di_scale, exponent)


def compute_E_di_gini(
    phi_species: np.ndarray,
    e_max: float = E_MAX_PA,
    e_min: float = E_MIN_PA,
    di_scale: float = 1.0,
    exponent: float = DI_EXPONENT,
) -> np.ndarray:
    """E from Gini-based DI (same power-law as Shannon DI)."""
    di = compute_di_gini(phi_species)
    return compute_E_di(di, e_max, e_min, di_scale, exponent)


def compute_E_di_pielou(
    phi_species: np.ndarray,
    e_max: float = E_MAX_PA,
    e_min: float = E_MIN_PA,
    di_scale: float = 1.0,
    exponent: float = DI_EXPONENT,
) -> np.ndarray:
    """E from Pielou evenness-based DI (same power-law as Shannon DI)."""
    di = compute_di_pielou(phi_species)
    return compute_E_di(di, e_max, e_min, di_scale, exponent)


# ─────────────────────────────────────────────────────────────────────────────
# JAX implementations (autodiff 対応)
# ─────────────────────────────────────────────────────────────────────────────

try:
    import jax.numpy as jnp

    def compute_E_di_jax(
        di,
        e_max=E_MAX_PA,
        e_min=E_MIN_PA,
        di_scale=DI_SCALE,
        exponent=DI_EXPONENT,
    ):
        """DI → E(DI) JAX differentiable."""
        r = jnp.clip(di / di_scale, 0, 1)
        return e_max * (1 - r) ** exponent + e_min * r

    def _hill_sigmoid_jax(x, m):
        xm = jnp.power(jnp.clip(x, 0.0, None), m)
        return xm / (1.0 + xm)

    def compute_E_phi_pg_jax(
        phi_species,
        e_max=E_MAX_PA,
        e_min=E_MIN_PA,
        phi_crit=PHI_PG_CRIT,
        hill_m=HILL_M,
    ):
        """φ_Pg → E(φ_Pg) JAX differentiable."""
        phi_pg = phi_species[..., IDX_PG]
        sig = _hill_sigmoid_jax(phi_pg / phi_crit, hill_m)
        return e_max - (e_max - e_min) * sig

    def compute_E_virulence_jax(
        phi_species,
        e_max=E_MAX_PA,
        e_min=E_MIN_PA,
        w_pg=W_PG,
        w_fn=W_FN,
        v_crit=V_CRIT,
        hill_m=HILL_M,
    ):
        """Virulence index → E(V) JAX differentiable."""
        v = w_pg * phi_species[..., IDX_PG] + w_fn * phi_species[..., IDX_FN]
        sig = _hill_sigmoid_jax(v / v_crit, hill_m)
        return e_max - (e_max - e_min) * sig

    def compute_di_jax(phi_species):
        """DI from phi — JAX differentiable."""
        eps = 1e-12
        phi_sum = jnp.sum(phi_species, axis=-1, keepdims=True)
        phi_sum_safe = jnp.where(phi_sum > eps, phi_sum, 1.0)
        p = phi_species / phi_sum_safe
        log_p = jnp.where(p > eps, jnp.log(p), 0.0)
        H = -jnp.sum(p * log_p, axis=-1)
        return 1.0 - H / jnp.log(5.0)

    def compute_E_eps_synergy_jax(
        phi_species,
        eps_rates=None,
        gamma=EPS_GAMMA,
        e_max=E_MAX_PA,
        e_min=E_MIN_PA,
    ):
        """EPS synergy model — JAX differentiable."""
        eps = jnp.array(EPS_RATES) if eps_rates is None else jnp.array(eps_rates)

        phi_sum = jnp.sum(phi_species, axis=-1, keepdims=True)
        phi_sum_safe = jnp.where(phi_sum > 1e-12, phi_sum, 1.0)
        p = phi_species / phi_sum_safe

        eps_total = jnp.clip(jnp.sum(p * eps, axis=-1), 0.0)

        active_mask = eps > 0
        p_active = p[..., active_mask]
        p_active_sum = jnp.sum(p_active, axis=-1, keepdims=True)
        p_active_sum_safe = jnp.where(p_active_sum > 1e-12, p_active_sum, 1.0)
        p_norm = p_active / p_active_sum_safe
        log_p = jnp.where(p_norm > 1e-12, jnp.log(p_norm), 0.0)
        H = -jnp.sum(p_norm * log_p, axis=-1)
        H_max = jnp.log(float(jnp.sum(active_mask)))
        cross_link = H / H_max

        M = eps_total * jnp.exp(gamma * cross_link)
        eps_active = eps[active_mask]
        eps_total_ref = float(jnp.mean(eps_active))
        M_ref = eps_total_ref * jnp.exp(gamma) * 1.1
        return e_min + (e_max - e_min) * jnp.clip(M / M_ref, 0.0, 1.0)

    HAS_JAX = True

except ImportError:
    HAS_JAX = False


# ─────────────────────────────────────────────────────────────────────────────
# Mooney-Rivlin 超弾性パラメータ
# ─────────────────────────────────────────────────────────────────────────────

C01_RATIO_DEFAULT = 0.15  # C01/C10 比 (Treloar 1975: ゴム系 0.1-0.25)


def compute_mooney_rivlin_params(
    E: np.ndarray,
    nu: float = 0.30,
    c01_ratio: float = C01_RATIO_DEFAULT,
) -> dict[str, np.ndarray]:
    """
    E, nu → Mooney-Rivlin パラメータ (C10, C01, D1).

    Mooney-Rivlin ひずみエネルギー密度:
      W = C10 (I1_bar - 3) + C01 (I2_bar - 3) + (1/D1)(J - 1)^2

    小ひずみ極限で線形弾性と一致:
      mu = 2(C10 + C01),  K = 2/D1
      → C10 = mu / (2(1 + c01_ratio))
      → C01 = C10 * c01_ratio

    c01_ratio = 0 のとき Neo-Hookean に退化。
    """
    E = np.asarray(E, dtype=np.float64)
    mu = E / (2.0 * (1.0 + nu))
    K = E / (3.0 * (1.0 - 2.0 * nu))
    K = np.where(K > 1e-20, K, 1e-20)
    C10 = 0.5 * mu / (1.0 + c01_ratio)
    C01 = C10 * c01_ratio
    D1 = 2.0 / K
    return {"C10": C10, "C01": C01, "D1": D1, "mu": mu, "K": K}


# ─────────────────────────────────────────────────────────────────────────────
# 粘弾性 (Prony series) パラメータ
# ─────────────────────────────────────────────────────────────────────────────

# 1-term Prony defaults for biofilm
# Ref: Peterson 2023 (Biophysical Reports 3:100130, P. aeruginosa biofilm)
# Ref: Stoodley 2002 (oral multi-species biofilm rheology)
PRONY_G1_HEALTHY = 0.3  # commensal: 低緩和 (堅い EPS crosslinks)
PRONY_G1_DEGRADED = 0.7  # dysbiotic: 高緩和 (分解 EPS)
PRONY_TAU_HEALTHY = 5.0  # s (健全: 短い緩和時間)
PRONY_TAU_DEGRADED = 50.0  # s (病的: 長い粘性流動時間)

# 粘性係数 (UMAT 用)
ETA_HEALTHY = 50.0  # Pa·s (堅いバイオフィルム)
ETA_DEGRADED = 500.0  # Pa·s (軟らかいバイオフィルム)


def compute_prony_params_di(
    di: np.ndarray,
    di_scale: float = DI_SCALE,
    g1_healthy: float = PRONY_G1_HEALTHY,
    g1_degraded: float = PRONY_G1_DEGRADED,
    tau_healthy: float = PRONY_TAU_HEALTHY,
    tau_degraded: float = PRONY_TAU_DEGRADED,
) -> dict[str, np.ndarray]:
    """
    DI → 1-term Prony series パラメータ.

    G(t) = G_inf + G_1 exp(-t/tau_1)
    g_1 = G_1/G_0 (shear relaxation ratio)
    G_inf = G_0 (1 - g_1)

    DI が高い (dysbiotic) ほど g_1 が大きく tau_1 が長い。
    """
    di = np.asarray(di, dtype=np.float64)
    r = np.clip(di / di_scale, 0.0, 1.0)
    g1 = g1_healthy + (g1_degraded - g1_healthy) * r
    tau1 = tau_healthy + (tau_degraded - tau_healthy) * r
    return {"g1": g1, "k1": np.zeros_like(g1), "tau1": tau1}


def compute_viscosity_di(
    di: np.ndarray,
    di_scale: float = DI_SCALE,
    eta_healthy: float = ETA_HEALTHY,
    eta_degraded: float = ETA_DEGRADED,
) -> np.ndarray:
    """DI → 粘性係数 eta [Pa·s] (UMAT 用)."""
    di = np.asarray(di, dtype=np.float64)
    r = np.clip(di / di_scale, 0.0, 1.0)
    return eta_healthy + (eta_degraded - eta_healthy) * r


def compute_relaxation_modulus(
    t: np.ndarray,
    G0: float,
    g1: float = 0.5,
    tau1: float = 10.0,
) -> np.ndarray:
    """
    1-term Prony series の緩和弾性率 G(t).

    G(t) = G0 * [(1 - g1) + g1 * exp(-t/tau1)]
    """
    t = np.asarray(t, dtype=np.float64)
    return G0 * ((1.0 - g1) + g1 * np.exp(-t / tau1))


# ─────────────────────────────────────────────────────────────────────────────
# 比較ユーティリティ
# ─────────────────────────────────────────────────────────────────────────────


def compute_all_E(
    phi_species: np.ndarray,
    mode: str = "all",
    di_scale: float = DI_SCALE,
) -> dict[str, np.ndarray]:
    """
    全 E(φ) モデルを一括計算する。

    Parameters
    ----------
    phi_species : (N, 5) — 菌種別 volume fraction
    mode : "di", "phi_pg", "virulence", "simpson", "gini", "pielou",
           "voigt", "reuss", or "all"
    di_scale : float — DI 正規化スケール (0D の場合は 1.0)

    Returns
    -------
    dict with keys for each enabled model
    """
    result = {}
    phi = np.asarray(phi_species)

    if mode in ("di", "all"):
        di = compute_di(phi)
        result["E_di"] = compute_E_di(di, di_scale=di_scale)
        result["DI"] = di
    if mode in ("phi_pg", "all"):
        result["E_phi_pg"] = compute_E_phi_pg(phi)
        result["phi_Pg"] = phi[..., IDX_PG]
    if mode in ("virulence", "all"):
        result["E_virulence"] = compute_E_virulence(phi)
        result["V"] = W_PG * phi[..., IDX_PG] + W_FN * phi[..., IDX_FN]
    if mode in ("simpson", "all"):
        result["E_simpson"] = compute_E_di_simpson(phi, di_scale=di_scale)
        result["DI_simpson"] = compute_di_simpson(phi)
    if mode in ("gini", "all"):
        result["E_gini"] = compute_E_di_gini(phi, di_scale=di_scale)
        result["DI_gini"] = compute_di_gini(phi)
    if mode in ("pielou", "all"):
        result["E_pielou"] = compute_E_di_pielou(phi, di_scale=di_scale)
        result["DI_pielou"] = compute_di_pielou(phi)
    if mode in ("voigt", "all"):
        result["E_voigt"] = compute_E_voigt(phi)
    if mode in ("reuss", "all"):
        result["E_reuss"] = compute_E_reuss(phi)
    if mode in ("eps_synergy", "all"):
        result["E_eps_synergy"] = compute_E_eps_synergy(phi)

    return result


# ─────────────────────────────────────────────────────────────────────────────
# CLI: モデル曲線の比較図
# ─────────────────────────────────────────────────────────────────────────────


def plot_model_comparison(outdir: str = None) -> str:
    """3つの E(φ) モデルの応答曲線を比較する図を生成。"""
    import matplotlib

    matplotlib.use("Agg")
    import matplotlib.pyplot as plt

    if outdir is None:
        import os

        outdir = os.path.join(
            os.path.dirname(os.path.abspath(__file__)), "figures", "material_models"
        )
    os.makedirs(outdir, exist_ok=True)

    fig, axes = plt.subplots(1, 3, figsize=(15, 5))

    # --- (a) DI model: E vs DI ---
    ax = axes[0]
    di_arr = np.linspace(0, 0.06, 200)
    for n in [1.0, 2.0, 4.0]:
        E = compute_E_di(di_arr, exponent=n)
        ax.plot(di_arr, E, lw=2, label=f"n={n:.0f}")
    ax.axvline(DI_SCALE, color="red", ls="--", lw=1, alpha=0.7, label=f"DI_scale={DI_SCALE:.4f}")
    ax.set_xlabel("DI (Dysbiotic Index)")
    ax.set_ylabel("E [Pa]")
    ax.set_title("(a) DI model: E(DI)\n[entropy-based, species-blind]")
    ax.legend(fontsize=8)
    ax.grid(alpha=0.3)
    ax.set_ylim(bottom=0)

    # --- (b) φ_Pg model: E vs φ_Pg ---
    ax = axes[1]
    phi_pg_arr = np.linspace(0, 0.15, 200)
    for m in [2, 4, 8]:
        sig = _hill_sigmoid(phi_pg_arr / PHI_PG_CRIT, m)
        E = E_MAX_PA - (E_MAX_PA - E_MIN_PA) * sig
        ax.plot(phi_pg_arr, E, lw=2, label=f"m={m}")
    ax.axvline(PHI_PG_CRIT, color="red", ls="--", lw=1, alpha=0.7, label=f"φ_crit={PHI_PG_CRIT}")
    ax.set_xlabel("φ_Pg (P. gingivalis fraction)")
    ax.set_ylabel("E [Pa]")
    ax.set_title("(b) φ_Pg model: E(φ_Pg)\n[mechanism-based, Pg-specific]")
    ax.legend(fontsize=8)
    ax.grid(alpha=0.3)
    ax.set_ylim(bottom=0)

    # --- (c) Virulence model: E vs V ---
    ax = axes[2]
    v_arr = np.linspace(0, 0.15, 200)
    sig = _hill_sigmoid(v_arr / V_CRIT, HILL_M)
    E_v = E_MAX_PA - (E_MAX_PA - E_MIN_PA) * sig
    ax.plot(v_arr, E_v, lw=2, color="purple", label=f"m={HILL_M:.0f}")
    ax.axvline(V_CRIT, color="red", ls="--", lw=1, alpha=0.7, label=f"V_crit={V_CRIT}")
    # annotate composition
    ax.annotate(
        f"V = {W_PG}·φ_Pg + {W_FN}·φ_Fn",
        xy=(0.5, 0.95),
        xycoords="axes fraction",
        fontsize=9,
        ha="center",
        va="top",
        bbox=dict(boxstyle="round,pad=0.3", fc="lightyellow"),
    )
    ax.set_xlabel("V (Virulence index)")
    ax.set_ylabel("E [Pa]")
    ax.set_title("(c) Virulence model: E(V)\n[Pg + Fn weighted]")
    ax.legend(fontsize=8)
    ax.grid(alpha=0.3)
    ax.set_ylim(bottom=0)

    plt.suptitle(
        "Material Models: DI (entropy) vs φ_Pg (mechanism) vs Virulence (Pg+Fn)",
        fontsize=12,
        y=1.02,
    )
    plt.tight_layout()

    path = os.path.join(outdir, "material_model_comparison.png")
    fig.savefig(path, dpi=200, bbox_inches="tight")
    plt.close(fig)
    print(f"  Material model comparison: {path}")
    return path


# ─────────────────────────────────────────────────────────────────────────────
# Viscoelastic (SLS/Zener) material model
# ─────────────────────────────────────────────────────────────────────────────
# Standard Linear Solid: spring E_inf in parallel with (spring E_1 + dashpot η)
#
#   E_0 = E_inf + E_1   (instantaneous modulus)
#   τ = η / E_1          (relaxation time)
#
# DI dependence:
#   - Commensal (DI≈0): dense EPS → high E_inf, slow relaxation (large τ)
#   - Dysbiotic (DI≈1): sparse/degraded EPS → low E_inf, fast relaxation (small τ)
#
# Ref: Shaw 2004 (τ=1-100s), Towler 2003 (E_0/E_inf=2-5),
#      Peterson & Stoodley 2015, Gloag 2019 (G'=160 Pa)

TAU_MAX_S = 60.0  # commensal max relaxation time [s]
TAU_MIN_S = 2.0  # dysbiotic min relaxation time [s]
E0_EINF_RATIO_MIN = 2.0  # commensal E_0/E_inf ratio
E0_EINF_RATIO_MAX = 5.0  # dysbiotic E_0/E_inf ratio
TAU_EXPONENT = 1.5  # power-law exponent for τ(DI)


def compute_viscoelastic_params_di(
    di: np.ndarray,
    e_max: float = E_MAX_PA,
    e_min: float = E_MIN_PA,
    di_scale: float = DI_SCALE,
    exponent: float = DI_EXPONENT,
    tau_max: float = TAU_MAX_S,
    tau_min: float = TAU_MIN_S,
    ratio_min: float = E0_EINF_RATIO_MIN,
    ratio_max: float = E0_EINF_RATIO_MAX,
    tau_exp: float = TAU_EXPONENT,
) -> dict:
    """
    DI → full SLS viscoelastic parameter set.

    Returns dict with E_inf, E_0, E_1, tau, eta arrays.
    """
    di = np.asarray(di, dtype=np.float64)
    r = np.clip(di / di_scale, 0.0, 1.0)

    E_inf = e_max * (1.0 - r) ** exponent + e_min * r
    ratio = ratio_min + (ratio_max - ratio_min) * r
    E_0 = E_inf * ratio
    E_1 = E_0 - E_inf
    tau = tau_max * (1.0 - r) ** tau_exp + tau_min * r
    eta = E_1 * tau

    return {"E_inf": E_inf, "E_0": E_0, "E_1": E_1, "tau": tau, "eta": eta}


if HAS_JAX:

    def compute_viscoelastic_params_di_jax(
        di,
        e_max=E_MAX_PA,
        e_min=E_MIN_PA,
        di_scale=DI_SCALE,
        exponent=DI_EXPONENT,
        tau_max=TAU_MAX_S,
        tau_min=TAU_MIN_S,
        ratio_min=E0_EINF_RATIO_MIN,
        ratio_max=E0_EINF_RATIO_MAX,
        tau_exp=TAU_EXPONENT,
    ):
        """DI → SLS viscoelastic params — JAX differentiable."""
        r = jnp.clip(di / di_scale, 0.0, 1.0)
        E_inf = e_max * (1.0 - r) ** exponent + e_min * r
        ratio = ratio_min + (ratio_max - ratio_min) * r
        E_0 = E_inf * ratio
        E_1 = E_0 - E_inf
        tau = tau_max * (1.0 - r) ** tau_exp + tau_min * r
        eta = E_1 * tau
        return {"E_inf": E_inf, "E_0": E_0, "E_1": E_1, "tau": tau, "eta": eta}


def sls_stress_relaxation(E_inf, E_1, tau, eps_0, t):
    """
    Analytical stress relaxation for SLS under step strain ε₀.

    σ(t) = [E_inf + E_1·exp(-t/τ)] · ε₀
    """
    return (np.asarray(E_inf) + np.asarray(E_1) * np.exp(-np.asarray(t) / np.asarray(tau))) * eps_0


def sls_creep_compliance(E_inf, E_1, tau, t):
    """
    Creep compliance J(t) for SLS under step stress σ₀.

    u(t) = σ₀ · J(t)
    """
    E_inf, E_1, tau, t = (np.asarray(x, dtype=np.float64) for x in (E_inf, E_1, tau, t))
    E_0 = E_inf + E_1
    eta = E_1 * tau
    tau_retard = eta / E_inf
    return 1.0 / E_inf - E_1 / (E_inf * E_0) * np.exp(-t / tau_retard)


if __name__ == "__main__":
    plot_model_comparison()
    print("\nModel parameters:")
    print(f"  DI:        s_DI={DI_SCALE}, n={DI_EXPONENT}")
    print(f"  phi_Pg:    φ_crit={PHI_PG_CRIT}, m={HILL_M}")
    print(f"  Virulence: w_Pg={W_PG}, w_Fn={W_FN}, V_crit={V_CRIT}, m={HILL_M}")
    print(f"  Voigt/Reuss: E_species={E_SPECIES_PA}")

    # Sanity check: commensal vs dysbiotic (S. oralis dominated)
    phi_test = np.array(
        [
            [0.20, 0.20, 0.20, 0.20, 0.20],  # commensal: uniform
            [0.80, 0.05, 0.05, 0.05, 0.05],  # dysbiotic: S.oralis dominant
            [0.05, 0.05, 0.05, 0.05, 0.80],  # dysbiotic: Pg dominant
        ]
    )
    res = compute_all_E(phi_test, di_scale=1.0)
    print("\nSanity check (commensal vs dysbiotic):")
    headers = [
        "E_di",
        "E_eps_syn",
        "E_simpson",
        "E_gini",
        "E_pielou",
        "E_voigt",
        "E_reuss",
        "E_phi_pg",
        "E_vir",
    ]
    key_map = {"E_vir": "E_virulence", "E_eps_syn": "E_eps_synergy"}  # display name -> result key
    print(f"  {'cond':>12}  " + "  ".join(f"{h:>10}" for h in headers))
    labels = ["commensal", "dysb(So)", "dysb(Pg)"]
    for i in range(3):
        row = []
        for h in headers:
            k = key_map.get(h, h)
            row.append(f"{res[k][i]:10.1f}" if k in res else "       -")
        print(f"  {labels[i]:>12}  " + "  ".join(row))

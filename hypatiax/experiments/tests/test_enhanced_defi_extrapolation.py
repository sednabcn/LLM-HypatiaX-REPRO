"""
test_enhanced_defi_extrapolation.py  — 73 Test Cases
======================================================
Fixes vs the 20-case version
─────────────────────────────
1. Hardcoded test_r2 = 0.3 fallback REMOVED.
   When the hybrid routes to NN (no LLM formula), the NN is evaluated
   directly on the held-out test split via _train_and_eval_nn().

2. NaN propagation fixed throughout.
   • Formula failures now return float("nan") instead of 0.
   • All statistics use np.nanmean / np.nanstd; NaN rows are filtered
     before t-tests and bootstrap sampling.
   • The per-case diagnostic table shows "nan" explicitly.
   • Bootstrap CI, LaTeX export, and radar plot all guard against NaN.

3. create_aggressive_split() fixed for 1-D X arrays.

4. Test suite expanded from 20 → 73 cases (drawn from 9 domains of the
   updated experiment_protocol_defi.py that has 77 unique formulas).

5. Output file named extrapolation_73cases_enhanced.json.

6. argparse description updated to reflect 73 cases.

7. _distance_llm_weight and _extrapolation_probe_degradation now guard
   against 1-D X arrays (same fix applied to create_aggressive_split).

8. na2 helper in the intractable-cases block moved outside the loop.

9. description setdefault applied before test_method calls so the
   correct description is used for formula generation.

10. stability_score / extrapolation_gap initialised to NaN for all
    results so downstream report code never hits a missing key.
"""

import json
import os
import sys
from pathlib import Path

import numpy as np
from scipy import stats
from sklearn.preprocessing import StandardScaler

# Add project root (4 levels up from this file's directory)
project_root = Path(__file__).parent.parent.parent.parent
sys.path.insert(0, str(project_root))

# FIX-suppA-1: honour $RESULTS_DIR env var so the script resolves output paths
# correctly regardless of the CWD it is launched from.  Falls back to the
# repo-relative default when not set (preserves local-run behaviour).
_RESULTS_DIR = Path(os.environ.get("RESULTS_DIR", project_root / "hypatiax" / "data" / "results"))

from hypatiax.protocols.experiment_protocol_defi import DeFiExperimentProtocol


class EnhancedExtrapolationTest:
    """73-case extrapolation test framework with statistical rigour and NaN-safe analysis."""

    def __init__(self):
        self.protocol = DeFiExperimentProtocol()
        self.results = []

    # ─────────────────────────────────────────────────────────────────────────
    # Data splitting
    # ─────────────────────────────────────────────────────────────────────────

    def create_aggressive_split(self, X, y, test_case_config):
        """
        Train on the lower 40 % of a chosen variable; test on the upper 60 %.
        Falls back to index-based split when the array is 1-D or too small.
        """
        var_idx = test_case_config.get("split_var_idx", 0)
        split_type = test_case_config.get("split_type", "high")

        # FIX: handle both 1-D and 2-D X arrays
        if X.ndim >= 2 and X.shape[1] > var_idx:
            var_values = X[:, var_idx]
        else:
            var_values = X.flatten()

        if split_type == "high":
            threshold  = np.percentile(var_values, 40)
            train_mask = var_values <= threshold
            test_mask  = var_values >  threshold
        else:
            threshold  = np.percentile(var_values, 60)
            train_mask = var_values >= threshold
            test_mask  = var_values <  threshold

        # Fallback: index-based if either partition is too small
        if train_mask.sum() < 20 or test_mask.sum() < 20:
            n          = len(X)
            idx        = np.arange(n)
            train_mask = idx < int(0.4 * n)
            test_mask  = ~train_mask

        return X[train_mask], y[train_mask], X[test_mask], y[test_mask]

    # ─────────────────────────────────────────────────────────────────────────
    # Routing improvement helpers (Fixes 1-4)
    # ─────────────────────────────────────────────────────────────────────────

    # Fix 2: symbols that signal the LLM formula is structurally superior for
    # extrapolation — any of these in the extracted code → force LLM routing.
    _TRANSCENDENTAL_TOKENS = [
        "math.exp", "np.exp", "exp(",
        "math.log", "np.log", "log(",
        "math.sqrt", "np.sqrt", "sqrt(",
        "norm.cdf", "norm.pdf", "scipy.stats",
        "np.maximum", "np.minimum", "max(", "min(",
        "math.sin", "np.sin", "math.cos", "np.cos",
        "**0.",  # fractional power e.g. x**0.5
    ]

    @classmethod
    def _formula_has_transcendental(cls, code: str) -> bool:
        """Return True if the LLM formula contains transcendental / piecewise ops."""
        low = code.lower()
        return any(t.lower() in low for t in cls._TRANSCENDENTAL_TOKENS)

    @staticmethod
    def _eval_formula_r2(llm_code, X, y_true, var_names):
        """
        Fix 5 — unified formula evaluator used for ALL LLM-path evaluation.

        Replaces hybrid.evaluate_llm_formula() which uses a different variable-
        binding and execution namespace than PureLLMBaseline.test_formula_accuracy(),
        causing silent divergence on quadratic / matrix formulas (e.g. Correlated
        Portfolio VaR scores +1.000 via pure LLM but -12 via evaluate_llm_formula).

        Uses execute_python_code_get_predictions — the same function already used
        in the ensemble path — so ALL formula execution goes through one code path.

        Returns (r2: float, success: bool).
        """
        try:
            from hypatiax.experiments.tests.hybrid_ensemble_system_defi_domain import (
                execute_python_code_get_predictions,
            )
            y_pred = execute_python_code_get_predictions(llm_code, X)
            if y_pred is None or np.any(np.isnan(y_pred)) or np.any(np.isinf(y_pred)):
                return float("nan"), False
            ss_res = np.sum((y_true - y_pred) ** 2)
            ss_tot = np.sum((y_true - np.mean(y_true)) ** 2)
            r2 = float(1 - ss_res / ss_tot) if ss_tot > 1e-10 else 0.0
            return r2, True
        except Exception:
            return float("nan"), False

    @staticmethod
    def _extrapolation_probe_degradation(X_train, y_train, probe_frac=0.15):
        """
        Fix 1 — measure how much NN generalises to the *edge* of training data.

        Splits X_train so the top  of the primary feature is the
        probe set and the rest is the fit set.  Trains a tiny MLP on the fit
        set and returns (in_r2 - probe_r2): large positive value → NN degrades
        quickly outside its comfort zone → route to LLM.
        """
        import torch
        from sklearn.preprocessing import StandardScaler

        from hypatiax.core.training.baseline_neural_network_defi_improved import (
            ImprovedNN,
        )

        n = len(X_train)
        split = int(n * (1 - probe_frac))
        # Sort by primary feature so probe = highest-value region
        # Guard: handle both 1-D and 2-D X_train (same fix as create_aggressive_split)
        primary_col = X_train[:, 0] if X_train.ndim >= 2 else X_train.flatten()
        order   = np.argsort(primary_col)
        X_sorted = X_train[order]
        y_sorted = y_train[order]

        X_fit, y_fit     = X_sorted[:split], y_sorted[:split]
        X_probe, y_probe = X_sorted[split:], y_sorted[split:]

        if len(X_probe) < 5 or len(X_fit) < 10:
            return 0.0   # not enough data to be meaningful

        sx = StandardScaler(); sy = StandardScaler()
        Xf = sx.fit_transform(X_fit)
        yf = sy.fit_transform(y_fit.reshape(-1,1)).flatten()

        model = ImprovedNN(X_fit.shape[1], [64, 32])
        opt   = torch.optim.Adam(model.parameters(), lr=0.001)
        crit  = torch.nn.MSELoss()
        Xt = torch.FloatTensor(Xf); yt = torch.FloatTensor(yf).reshape(-1,1)
        model.train()
        for _ in range(200):
            opt.zero_grad(); loss = crit(model(Xt), yt); loss.backward(); opt.step()

        def _r2(y_true, y_pred):
            ss_res = np.sum((y_true - y_pred) ** 2)
            ss_tot = np.sum((y_true - np.mean(y_true)) ** 2)
            return float(1 - ss_res / ss_tot) if ss_tot > 1e-10 else 0.0

        model.eval()
        with torch.no_grad():
            r2_in    = _r2(y_fit,   sy.inverse_transform(model(Xt).numpy()).flatten())
            Xp = torch.FloatTensor(sx.transform(X_probe))
            r2_probe = _r2(y_probe, sy.inverse_transform(model(Xp).numpy()).flatten())

        return max(0.0, r2_in - r2_probe)   # degradation ≥ 0

    @staticmethod
    def _distance_llm_weight(X_test, X_train, base_weight=0.3):
        """
        Fix 4 — compute LLM blend weight based on how far test points lie
        outside the training feature range.

        base_weight : weight given to LLM even when test is fully in-distribution
        Returns a scalar in [base_weight, 1.0].
        """
        # Guard: handle both 1-D and 2-D arrays (consistent with create_aggressive_split)
        if X_test.ndim == 1:
            X_test  = X_test.reshape(-1, 1)
        if X_train.ndim == 1:
            X_train = X_train.reshape(-1, 1)
        train_min = X_train.min(axis=0)
        train_max = X_train.max(axis=0)
        outside   = np.mean(
            np.any((X_test < train_min) | (X_test > train_max), axis=1)
        )
        # Linearly interpolate: 0 outside → base_weight, 1.0 outside → 1.0 LLM
        return float(base_weight + (1.0 - base_weight) * outside)

    # ─────────────────────────────────────────────────────────────────────────
    # NN helper — shared by neural_network path and hybrid fallback
    # ─────────────────────────────────────────────────────────────────────────

    # Deterministic seed used across all NN training calls (Open Issue 1).
    # Set once here so every call to _train_and_eval_nn and the probe NN
    # produces the same initialisation for a given case, eliminating the
    # run-to-run variance that previously caused NN-routed hybrid scores
    # to differ between resume sessions.
    _NN_SEED: int = 2024

    def _train_and_eval_nn(self, X_train, y_train, X_test, y_test,
                           seed: int = None):
        """
        Train a small MLP on (X_train, y_train) and evaluate on both splits.

        Parameters
        ----------
        seed : int, optional
            Random seed for torch and numpy.  Defaults to cls._NN_SEED so
            results are deterministic across checkpoint resume sessions.

        Returns dict: {train_r2, test_r2, success,
                       y_pred_train, y_pred_test}
        """
        if seed is None:
            seed = self._NN_SEED
        import torch
        torch.manual_seed(seed)
        np.random.seed(seed)
        from hypatiax.core.training.baseline_neural_network_defi_improved import (
            ImprovedNN,
        )

        scaler_X = StandardScaler()
        scaler_y = StandardScaler()

        X_tr_s = scaler_X.fit_transform(X_train)
        y_tr_s = scaler_y.fit_transform(y_train.reshape(-1, 1)).flatten()

        model     = ImprovedNN(X_train.shape[1], [128, 64, 32])
        optimiser = torch.optim.Adam(model.parameters(), lr=0.001)
        criterion = torch.nn.MSELoss()

        X_tr_t = torch.FloatTensor(X_tr_s)
        y_tr_t = torch.FloatTensor(y_tr_s).reshape(-1, 1)

        model.train()
        for _ in range(300):
            optimiser.zero_grad()
            loss = criterion(model(X_tr_t), y_tr_t)
            loss.backward()
            optimiser.step()

        def _decode(pred_scaled):
            """Inverse-scale raw NN output → original units."""
            return scaler_y.inverse_transform(
                pred_scaled.reshape(-1, 1)
            ).flatten()

        def _r2(y_true, y_pred):
            ss_res = np.sum((y_true - y_pred) ** 2)
            ss_tot = np.sum((y_true - np.mean(y_true)) ** 2)
            return float(1 - ss_res / ss_tot) if ss_tot > 1e-10 else 0.0

        model.eval()
        with torch.no_grad():
            y_pred_train = _decode(model(X_tr_t).numpy().flatten())
            X_te_s       = scaler_X.transform(X_test)
            X_te_t       = torch.FloatTensor(X_te_s)
            y_pred_test  = _decode(model(X_te_t).numpy().flatten())

        return {
            "train_r2":    _r2(y_train, y_pred_train),
            "test_r2":     _r2(y_test,  y_pred_test),
            "success":     True,
            "y_pred_train": y_pred_train,   # raw array — needed by ensemble blend
            "y_pred_test":  y_pred_test,    # raw array — needed by ensemble blend
        }

    # ─────────────────────────────────────────────────────────────────────────
    # 73 test-case catalogue
    # ─────────────────────────────────────────────────────────────────────────

    def get_test_cases(self):
        """
        Return 73 extrapolation test cases covering all 9 protocol domains.
        'name' must be a case-insensitive substring of the matching protocol
        description so the substring lookup in run_full_test() succeeds.
        """
        return [
            # ==============================================================
            # EASY  (24 cases) — linear / simple-rational / sqrt-of-time
            # ==============================================================
            {"name": "Value at Risk at 95%",
             "domain": "risk",          "difficulty": "easy",
             "formula_type": "linear",  "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Value at Risk at 99%",
             "domain": "risk_var",      "difficulty": "easy",
             "formula_type": "linear",  "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Expected Shortfall at 95%",
             "domain": "risk",          "difficulty": "easy",
             "formula_type": "linear",  "num_samples": 200,
             "config": {"split_var_idx": 1, "split_type": "high"}},

            {"name": "Expected Shortfall at 99%",
             "domain": "expected_shortfall", "difficulty": "easy",
             "formula_type": "linear",       "num_samples": 200,
             "config": {"split_var_idx": 1, "split_type": "high"}},

            {"name": "Collateral Ratio",
             "domain": "lending",            "difficulty": "easy",
             "formula_type": "rational_simple", "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Reserve Ratio",
             "domain": "amm",                "difficulty": "easy",
             "formula_type": "rational_simple", "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Simple Staking APY",
             "domain": "staking",       "difficulty": "easy",
             "formula_type": "linear",  "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Loan-to-Value",
             "domain": "lending",            "difficulty": "easy",
             "formula_type": "rational_simple", "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Spot price from AMM",
             "domain": "amm",                "difficulty": "easy",
             "formula_type": "rational_simple", "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "LP share percentage",
             "domain": "amm",                "difficulty": "easy",
             "formula_type": "rational_simple", "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Long position unrealized PnL",
             "domain": "trading",       "difficulty": "easy",
             "formula_type": "linear",  "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Short position unrealized PnL",
             "domain": "trading",       "difficulty": "easy",
             "formula_type": "linear",  "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Funding rate cost",
             "domain": "trading",       "difficulty": "easy",
             "formula_type": "linear",  "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Validator commission adjusted",
             "domain": "staking",       "difficulty": "easy",
             "formula_type": "linear",  "num_samples": 200,
             "config": {"split_var_idx": 1, "split_type": "high"}},

            {"name": "Slashing penalty",
             "domain": "staking",       "difficulty": "easy",
             "formula_type": "linear",  "num_samples": 200,
             "config": {"split_var_idx": 1, "split_type": "high"}},

            {"name": "Protocol reserve accumulation",
             "domain": "lending",       "difficulty": "easy",
             "formula_type": "linear",  "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Leveraged position notional",
             "domain": "trading",       "difficulty": "easy",
             "formula_type": "linear",  "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Cross-margin available balance",
             "domain": "liquidation",   "difficulty": "easy",
             "formula_type": "linear",  "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Realized PnL for long",
             "domain": "liquidation",   "difficulty": "easy",
             "formula_type": "linear",  "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "LP fee earnings",
             "domain": "liquidity",          "difficulty": "easy",
             "formula_type": "rational_simple", "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Multi-day Value at Risk",
             "domain": "risk_var",      "difficulty": "easy",
             "formula_type": "algebraic", "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "ES scaling for multi-day",
             "domain": "expected_shortfall", "difficulty": "easy",
             "formula_type": "algebraic",    "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Annualised Portfolio tracking error",
             "domain": "risk_var",       "difficulty": "easy",
             "formula_type": "algebraic", "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Incremental VaR",
             "domain": "risk_var",       "difficulty": "easy",
             "formula_type": "linear",   "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            # ==============================================================
            # MEDIUM  (28 cases) — rational / polynomial / exponential
            # ==============================================================
            {"name": "Liquidation Price Long",
             "domain": "trading",        "difficulty": "medium",
             "formula_type": "rational", "num_samples": 200,
             "config": {"split_var_idx": 1, "split_type": "high"}},

            {"name": "Liquidation Price Short",
             "domain": "trading",        "difficulty": "medium",
             "formula_type": "rational", "num_samples": 200,
             "config": {"split_var_idx": 1, "split_type": "high"}},

            {"name": "Constant Product Price Impact",
             "domain": "amm",            "difficulty": "medium",
             "formula_type": "rational", "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Effective Leverage",
             "domain": "trading",        "difficulty": "medium",
             "formula_type": "rational", "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Borrowing Interest",
             "domain": "lending",           "difficulty": "medium",
             "formula_type": "exponential", "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Compounding Staking Returns",
             "domain": "staking",           "difficulty": "medium",
             "formula_type": "exponential", "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Portfolio Sharpe Ratio",
             "domain": "risk",           "difficulty": "medium",
             "formula_type": "rational", "num_samples": 200,
             "config": {"split_var_idx": 1, "split_type": "high"}},

            {"name": "APY calculation",
             "domain": "liquidity",         "difficulty": "medium",
             "formula_type": "exponential", "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Capital efficiency",
             "domain": "liquidity",      "difficulty": "medium",
             "formula_type": "rational", "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "AMM output amount",
             "domain": "amm",            "difficulty": "medium",
             "formula_type": "rational", "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Price slippage percentage",
             "domain": "amm",            "difficulty": "medium",
             "formula_type": "rational", "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Information ratio",
             "domain": "risk_var",       "difficulty": "medium",
             "formula_type": "rational", "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Utilization rate of DeFi",
             "domain": "lending",        "difficulty": "medium",
             "formula_type": "rational", "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Borrow APY from utilization",
             "domain": "lending",        "difficulty": "medium",
             "formula_type": "linear",   "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Supply APY from borrow",
             "domain": "lending",        "difficulty": "medium",
             "formula_type": "linear",   "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Health factor",
             "domain": "lending",        "difficulty": "medium",
             "formula_type": "rational", "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Fee APY from trading",
             "domain": "liquidity",      "difficulty": "medium",
             "formula_type": "rational", "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Concentrated liquidity position width",
             "domain": "liquidity",      "difficulty": "medium",
             "formula_type": "rational", "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Inflation-adjusted staking",
             "domain": "staking",        "difficulty": "medium",
             "formula_type": "rational", "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Staking position annual growth",
             "domain": "staking",           "difficulty": "medium",
             "formula_type": "exponential", "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Epoch reward per",
             "domain": "staking",        "difficulty": "medium",
             "formula_type": "rational", "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "AMM arbitrage profit",
             "domain": "amm",            "difficulty": "medium",
             "formula_type": "linear",   "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"},
             "extrapolation_intractable": True,
             "intractable_reason": "profit = arb_amount*(ext_price - amm_price) — LLM formula has wrong additive constant; tiny constant error explodes at large arb_amount values in the test split"},

            {"name": "Liquidation bonus",
             "domain": "lending",        "difficulty": "medium",
             "formula_type": "linear",   "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Component ES for",
             "domain": "expected_shortfall", "difficulty": "medium",
             "formula_type": "linear",       "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Position margin ratio",
             "domain": "liquidation",    "difficulty": "medium",
             "formula_type": "rational", "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Partial liquidation amount",
             "domain": "liquidation",    "difficulty": "medium",
             "formula_type": "linear",   "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "VaR scaling by confidence",
             "domain": "trading",        "difficulty": "medium",
             "formula_type": "linear",   "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "LP position rebalancing",
             "domain": "liquidity",      "difficulty": "medium",
             "formula_type": "linear",   "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Impermanent loss breakeven",
             "domain": "liquidity",      "difficulty": "medium",
             "formula_type": "rational", "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"},
             "extrapolation_intractable": True,
             "intractable_reason": "Breakeven condition involves implicit solving — aggressive high-split puts test set in a regime where NN R2 collapses catastrophically; LLM 1.000 train/test is a degenerate-split artefact"},

            # ==============================================================
            # HARD  (20 cases) — transcendental / algebraic / piecewise
            # ==============================================================
            {"name": "Impermanent loss percentage",
             "domain": "amm",                    "difficulty": "hard",
             "formula_type": "algebraic_with_sqrt", "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Optimal LP Position (Kelly)",
             "domain": "liquidity",              "difficulty": "hard",
             "formula_type": "rational_with_min", "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"},
             "extrapolation_intractable": True,
             "intractable_reason": "min() clamp creates a discontinuous boundary — out-of-range test set falls entirely in the clipped region, collapsing y-variance to zero"},

            {"name": "Options Delta",
             "domain": "derivatives",            "difficulty": "hard",
             "formula_type": "transcendental",   "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"},
             "extrapolation_intractable": True,
             "intractable_reason": "CDF (Φ) is transcendental — extrapolation beyond training volatility/moneyness range is structurally undefined for all methods"},

            {"name": "Black-Scholes Call Price",
             "domain": "derivatives",            "difficulty": "hard",
             "formula_type": "transcendental",   "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"},
             "extrapolation_intractable": True,
             "intractable_reason": "CDF-based pricing formula — same transcendental extrapolation failure as Options Delta"},

            {"name": "Volatility Smile Skew",
             "domain": "derivatives",            "difficulty": "hard",
             "formula_type": "polynomial",       "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Multi-Collateral LTV",
             "domain": "lending",                "difficulty": "hard",
             "formula_type": "weighted_aggregate", "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Correlated Portfolio VaR",
             "domain": "risk",                   "difficulty": "hard",
             "formula_type": "quadratic_form",   "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Impermanent loss in constant product",
             "domain": "amm",                    "difficulty": "hard",
             "formula_type": "algebraic_with_sqrt", "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Constant product formula",
             "domain": "amm",                    "difficulty": "hard",
             "formula_type": "rational",         "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Convexity Adjustment",
             "domain": "amm",                    "difficulty": "hard",
             "formula_type": "algebraic",        "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Liquidation price for leveraged long",
             "domain": "liquidation",            "difficulty": "hard",
             "formula_type": "rational",         "num_samples": 200,
             "config": {"split_var_idx": 1, "split_type": "high"}},

            {"name": "Liquidation price for leveraged short",
             "domain": "liquidation",            "difficulty": "hard",
             "formula_type": "rational",         "num_samples": 200,
             "config": {"split_var_idx": 1, "split_type": "high"}},

            {"name": "Maximum safe leverage",
             "domain": "liquidation",            "difficulty": "hard",
             "formula_type": "rational",         "num_samples": 200,
             "config": {"split_var_idx": 1, "split_type": "high"}},

            {"name": "Required collateral",
             "domain": "liquidation",            "difficulty": "hard",
             "formula_type": "rational",         "num_samples": 200,
             "config": {"split_var_idx": 1, "split_type": "high"}},

            {"name": "Forward price for derivative",
             "domain": "derivatives",            "difficulty": "hard",
             "formula_type": "exponential",      "num_samples": 200,
             "config": {"split_var_idx": 1, "split_type": "high"}},

            {"name": "Put option intrinsic",
             "domain": "derivatives",            "difficulty": "hard",
             "formula_type": "piecewise_linear", "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"},
             "extrapolation_intractable": True,
             "intractable_reason": "max(K-S,0) piecewise boundary — aggressive split puts test set fully in-the-money or OTM, making R² degenerate"},

            {"name": "Call option intrinsic",
             "domain": "derivatives",            "difficulty": "hard",
             "formula_type": "piecewise_linear", "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Put-call parity",
             "domain": "derivatives",            "difficulty": "hard",
             "formula_type": "exponential",      "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Simple options moneyness",
             "domain": "derivatives",            "difficulty": "hard",
             "formula_type": "rational",         "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},

            {"name": "Uniswap V3 virtual",
             "domain": "amm",                    "difficulty": "hard",
             "formula_type": "algebraic_with_sqrt", "num_samples": 200,
             "config": {"split_var_idx": 0, "split_type": "high"}},
        ]

    # ─────────────────────────────────────────────────────────────────────────
    # Per-method runners
    # ─────────────────────────────────────────────────────────────────────────

    def test_method(self, method_name, test_case,
                    X_train, y_train, X_test, y_test,
                    var_names, metadata):
        """
        Evaluate one method on one test case.
        Returns dict with at least: train_r2, test_r2, success.
        On formula failure returns float('nan') — never 0 — so that NaN-aware
        statistics can distinguish a genuine score of 0 from a failure.
        """

        # ── Pure LLM ────────────────────────────────────────────────────────
        if method_name == "pure_llm":
            from hypatiax.core.base_pure_llm.baseline_pure_llm_defi_discovery import (
                PureLLMBaseline,
            )

            baseline     = PureLLMBaseline()
            result       = baseline.generate_formula(
                test_case.get("description", test_case["name"]),
                test_case["domain"], var_names, metadata,
            )
            train_m = baseline.test_formula_accuracy(
                result, X_train, y_train, var_names, verbose=False
            )
            test_m  = baseline.test_formula_accuracy(
                result, X_test,  y_test,  var_names, verbose=False
            )

            # FIX: return nan (not 0) on failure so stats can filter correctly
            train_r2 = (
                float(train_m["r2"]) if train_m.get("success") else float("nan")
            )
            test_r2 = (
                float(test_m["r2"])  if test_m.get("success")  else float("nan")
            )

            return {
                "train_r2": train_r2,
                "test_r2":  test_r2,
                "success":  train_m.get("success", False),
            }

        # ── Neural network ──────────────────────────────────────────────────
        elif method_name == "neural_network":
            return self._train_and_eval_nn(X_train, y_train, X_test, y_test)

        # ── Hybrid system ───────────────────────────────────────────────────
        elif method_name == "hybrid":
            from hypatiax.core.generation.hybrid_defi_system.hybrid_system_nn_defi_domain import (
                EnhancedHybridSystemDeFi,
            )

            hybrid       = EnhancedHybridSystemDeFi()
            train_result = hybrid.hybrid_predict(
                test_case.get("description", test_case["name"]),
                test_case["domain"],
                X_train, y_train, var_names, metadata,
                verbose=False,
            )

            decision   = train_result.get("decision", "nn")
            llm_result = train_result.get("llm_result", {})
            llm_code   = llm_result.get("python_code", "N/A")
            has_formula = bool(llm_code and llm_code != "N/A")

            # ── Routing improvements (Fixes 1, 2) ───────────────────────────
            # These run *after* the hybrid's own decision and may upgrade
            # an "nn" or "ensemble" decision to "llm" when evidence says the
            # NN will fail on extrapolation.

            # Extract hybrid's own LLM train R² to guard routing overrides.
            # If the LLM formula was bad at training time (R² ≤ 0), forcing
            # the test path to use it produces catastrophic scores (cases 31, 40).
            _llm_train_r2 = float(
                train_result.get("llm_result", {})
                .get("metrics", {})
                .get("r2", 0.0) or 0.0
            )
            _llm_formula_trustworthy = has_formula and (_llm_train_r2 > 0.0)

            if _llm_formula_trustworthy and decision in ("nn", "ensemble"):
                # Fix 2: formula contains transcendental / piecewise ops → LLM wins.
                # Guard: only override if LLM formula actually fit training data.
                if self._formula_has_transcendental(llm_code):
                    decision = "llm"

            if _llm_formula_trustworthy and decision in ("nn", "ensemble"):
                # Fix 1: probe NN degradation at the edge of training data.
                # If the NN loses ≥0.15 R² from fit-region to probe-region,
                # the hybrid routes to LLM instead.
                # Guard: same — only override when LLM formula is trustworthy.
                try:
                    degradation = self._extrapolation_probe_degradation(
                        X_train, y_train, probe_frac=0.15
                    )
                    if degradation >= 0.15:
                        decision = "llm"
                except Exception:
                    pass   # probe failure is non-fatal; keep original decision

            # FIX 3: evaluate the test split using whichever component the hybrid
            # *actually chose at training time*.  The old code always used the LLM
            # formula path when any formula existed, which produced NaN whenever
            # the formula evaluation failed — even when decision was "nn".

            if decision == "llm":
                # Hybrid committed to the LLM formula → evaluate it on test set.
                # Fix 5: use unified _eval_formula_r2 instead of
                # hybrid.evaluate_llm_formula, which uses a different variable-
                # binding namespace and silently diverges from PureLLMBaseline
                # on quadratic / matrix formulas (e.g. Correlated Portfolio VaR).
                test_r2, _ok = self._eval_formula_r2(llm_code, X_test, y_test, var_names)
                # Safety net: if unified evaluator also fails, try evaluate_llm_formula
                if not _ok or np.isnan(test_r2):
                    _fallback = hybrid.evaluate_llm_formula(
                        {"python_code": llm_code},
                        X_test, y_test, var_names, verbose=False,
                    )
                    test_r2 = float(_fallback["r2"]) if _fallback.get("success") else float("nan")

            elif decision == "ensemble" and has_formula:
                # Hybrid blended LLM + NN → blend predictions on test set too,
                # using the same uncertainty-weighted scheme from the ensemble module.
                # Fix 5: evaluate LLM on test set via unified evaluator
                _llm_test_r2, llm_test_ok = self._eval_formula_r2(
                    llm_code, X_test, y_test, var_names
                )
                # Wrap result in a dict so downstream code can use .get("r2", ...)
                test_m_llm = {"r2": _llm_test_r2, "success": llm_test_ok}

                # Train fresh NN on train split and get raw test predictions
                nn_m = self._train_and_eval_nn(X_train, y_train, X_test, y_test)

                if llm_test_ok:
                    # Reconstruct LLM test predictions from the r2 score is not
                    # possible, so re-run the formula to get actual y_pred values.
                    try:
                        from hypatiax.experiments.tests.hybrid_ensemble_system_defi_domain import (
                            ensemble_llm_nn,
                            execute_python_code_get_predictions,
                        )
                        llm_pred = execute_python_code_get_predictions(llm_code, X_test)
                        nn_pred  = nn_m["y_pred_test"]
                        llm_train_r2 = float(
                            train_result.get("llm_result", {})
                            .get("metrics", {})
                            .get("r2", 0.0) or 0.0
                        )
                        # Fix 4: distance-gated blend weight.
                        # When test points lie outside training range (always
                        # true in extrapolation), shift weight toward LLM.
                        llm_w = self._distance_llm_weight(X_test, X_train,
                                                          base_weight=0.3)
                        nn_w  = 1.0 - llm_w
                        ensemble_pred, _ = ensemble_llm_nn(
                            llm_pred, nn_pred, y_test,
                            llm_r2=llm_train_r2 * llm_w,
                            nn_r2=nn_m["train_r2"] * nn_w,
                        )
                        ss_res  = np.sum((y_test - ensemble_pred) ** 2)
                        ss_tot  = np.sum((y_test - np.mean(y_test)) ** 2)
                        test_r2 = float(1 - ss_res / ss_tot) if ss_tot > 1e-10 else 0.0
                    except Exception:
                        # Fallback: take the better of LLM and NN on test
                        test_r2 = max(
                            float(test_m_llm.get("r2", float("nan"))),
                            nn_m["test_r2"],
                        )
                else:
                    # LLM failed on test set → fall back to NN test result
                    test_r2 = nn_m["test_r2"]

            else:
                # decision == "nn" (or anything unexpected): use NN on test set.
                # Fix 3: if a valid, trustworthy LLM formula exists, augment X
                # with LLM preds so the NN learns residuals rather than fighting
                # from scratch. Guard: skip augmentation if LLM train R² ≤ 0
                # (bad formula would poison the NN input).
                if _llm_formula_trustworthy:
                    try:
                        from hypatiax.experiments.tests.hybrid_ensemble_system_defi_domain import (
                            execute_python_code_get_predictions,
                        )
                        llm_pred_train = execute_python_code_get_predictions(llm_code, X_train)
                        llm_pred_test  = execute_python_code_get_predictions(llm_code, X_test)
                        if (llm_pred_train is not None and llm_pred_test is not None
                                and not np.any(np.isnan(llm_pred_train))
                                and not np.any(np.isnan(llm_pred_test))):
                            X_train_aug = np.column_stack([X_train, llm_pred_train])
                            X_test_aug  = np.column_stack([X_test,  llm_pred_test])
                            nn_m    = self._train_and_eval_nn(X_train_aug, y_train,
                                                              X_test_aug,  y_test)
                        else:
                            nn_m    = self._train_and_eval_nn(X_train, y_train, X_test, y_test)
                    except Exception:
                        nn_m    = self._train_and_eval_nn(X_train, y_train, X_test, y_test)
                else:
                    nn_m    = self._train_and_eval_nn(X_train, y_train, X_test, y_test)
                test_r2 = nn_m["test_r2"]

            return {
                "train_r2": float(train_result["evaluation"]["r2"]),
                "test_r2":  float(test_r2),
                "decision": decision,
                "success":  True,
            }

    # ─────────────────────────────────────────────────────────────────────────
    # Main test runner
    # ─────────────────────────────────────────────────────────────────────────

    # ─────────────────────────────────────────────────────────────────────────
    # Checkpoint helpers
    # ─────────────────────────────────────────────────────────────────────────

    @staticmethod
    def _checkpoint_path() -> Path:
        # FIX-suppA-1: use env-aware _RESULTS_DIR so checkpoint resolves correctly
        # regardless of CWD (i.e. when launched from REPO_ROOT via run_all.sh).
        return _RESULTS_DIR / "extrapolation_73cases_enhanced.json"

    @classmethod
    def _load_checkpoint(cls):
        """
        Load a previously saved (partial or complete) results file.

        Returns:
            (results_list, n_completed)
            results_list  — list of result dicts already saved, in order.
            n_completed   — number of completed cases (== len(results_list)).
            Returns ([], 0) when no checkpoint file exists or it is unreadable.
        """
        cp = cls._checkpoint_path()
        if not cp.exists():
            return [], 0
        try:
            with open(cp) as f:
                data = json.load(f)
            if not isinstance(data, list):
                return [], 0
            # Deduplicate: if a case name appears more than once (checkpoint
            # resume artefact), keep only the last occurrence so re-runs do
            # not inflate n.
            seen: dict = {}
            for item in data:
                name = item.get("test_case", id(item))
                seen[name] = item          # last write wins
            data = list(seen.values())
            return data, len(data)
        except (json.JSONDecodeError, OSError):
            return [], 0

    def _save_checkpoint(self, all_results):
        """Write current results list to the checkpoint file (atomic-ish)."""
        self._save_results(all_results)

    def run_full_test(self, verbose: bool = False, start_from: int = 1):
        """
        Run the 73-case extrapolation test, with checkpoint/resume support.

        Args:
            verbose:    Print extra per-case output.
            start_from: 1-based case index to start from.  If a checkpoint
                        file already has more completed cases than start_from,
                        the checkpoint takes precedence (we never re-run
                        already-completed cases).
        """

        test_cases = self.get_test_cases()
        total      = len(test_cases)

        # ── Load existing checkpoint ───────────────────────────────────────
        existing_results, n_done = self._load_checkpoint()

        # Honour whichever is further ahead: explicit start_from or checkpoint
        effective_start = max(start_from, n_done + 1)
        is_resuming     = effective_start > 1

        print("=" * 80)
        if is_resuming:
            print(f"EXTRAPOLATION TEST — RESUMING FROM CASE {effective_start}/{total}")
            print(f"  ({n_done} cases already completed, loaded from checkpoint)")
        else:
            print("ENHANCED EXTRAPOLATION TEST — 73 CASES")
        print("=" * 80)
        print("Statistical power: n=73 gives >0.8 power at medium effect size")
        print("Aggressive splits: train 40%, test 60% (out-of-range)")
        print("NaN handling: formula failures reported as NaN, not 0")
        print("Checkpoint: results saved after every completed case")
        print("=" * 80)

        # Start from whatever was already done
        all_results = list(existing_results)

        for i, test_case in enumerate(test_cases, 1):

            # ── Skip already-completed cases ──────────────────────────────
            if i < effective_start:
                if verbose:
                    print(f"[{i:02d}/{total}] ⏭  {test_case['name']} — skipping (already done)")
                else:
                    print(f"[{i:02d}/{total}] ⏭  skipping: {test_case['name']}")
                continue

            print(f"\n[{i:02d}/{total}] {test_case['name']}  ({test_case['difficulty'].upper()})")
            print(f"  Domain: {test_case['domain']},  Type: {test_case['formula_type']}")

            try:
                protocol_cases = self.protocol.load_test_data(
                    test_case["domain"], num_samples=test_case["num_samples"]
                )

                # Substring match — first description containing the name wins
                matching_case = None
                for desc, X, y, var_names, meta in protocol_cases:
                    if test_case["name"].lower() in desc.lower():
                        matching_case = (desc, X, y, var_names, meta)
                        break

                if not matching_case:
                    print(f"  ⚠️  No match for '{test_case['name']}' in "
                          f"domain '{test_case['domain']}' — skipping")
                    continue

                desc, X_full, y_full, var_names, metadata = matching_case
                metadata["extrapolation_test"] = True
                metadata["difficulty"]         = test_case["difficulty"]
                metadata["formula_type"]       = test_case["formula_type"]
                # Set description BEFORE test_method calls so generate_formula
                # receives the full protocol description, not just the short name.
                test_case.setdefault("description", desc)

                X_train, y_train, X_test, y_test = self.create_aggressive_split(
                    X_full, y_full, test_case["config"]
                )
                print(f"  Split → Train: {len(X_train)}, Test: {len(X_test)}")

                results = {}
                for method in ["pure_llm", "neural_network", "hybrid"]:
                    try:
                        result = self.test_method(
                            method, test_case,
                            X_train, y_train, X_test, y_test,
                            var_names, metadata,
                        )
                        results[method] = result

                        # Always initialise these keys so the report never hits
                        # a missing-key error even when success=False.
                        result.setdefault("extrapolation_gap",  float("nan"))
                        result.setdefault("stability_score",    float("nan"))

                        if result.get("success", False):
                            tr = result.get("train_r2", float("nan"))
                            te = result.get("test_r2",  float("nan"))
                            result["extrapolation_gap"] = (
                                float(tr - te)
                                if not (np.isnan(tr) or np.isnan(te))
                                else float("nan")
                            )
                            result["stability_score"] = (
                                float(te / tr)
                                if (not np.isnan(tr) and not np.isnan(te)
                                    and abs(tr) > 1e-6)
                                else float("nan")
                            )

                        def _fmt(v):
                            if v is None or (isinstance(v, float) and np.isnan(v)):
                                return "    nan"
                            return f"{v:7.4f}"

                        tr = result.get("train_r2", float("nan"))
                        te = result.get("test_r2",  float("nan"))
                        print(f"  {method:15s}: Train R²={_fmt(tr)},  Test R²={_fmt(te)}")

                    except Exception as e:
                        print(f"  {method:15s}: ERROR — {str(e)[:60]}")
                        results[method] = {
                            "train_r2": float("nan"),
                            "test_r2":  float("nan"),
                            "success":  False,
                            "error":    str(e),
                        }

                all_results.append({
                    "test_case":    test_case["name"],
                    "difficulty":   test_case["difficulty"],
                    "formula_type": test_case["formula_type"],
                    "results":      results,
                })

                # ── Write checkpoint after every completed case ────────────
                self._save_checkpoint(all_results)
                print(f"  💾 Checkpoint saved ({len(all_results)}/{total} cases)")

            except Exception as e:
                print(f"  ❌ Outer error: {e}")
                continue

        # Statistical report + final save
        self.generate_statistical_report(all_results)
        self._save_results(all_results)
        return all_results

    # ─────────────────────────────────────────────────────────────────────────
    # Results persistence
    # ─────────────────────────────────────────────────────────────────────────

    def _save_results(self, all_results):
        def _json_default(obj):
            if isinstance(obj, np.integer):  return int(obj)
            if isinstance(obj, np.floating):
                return None if (np.isnan(obj) or np.isinf(obj)) else float(obj)
            if isinstance(obj, np.bool_):    return bool(obj)
            if isinstance(obj, np.ndarray):  return obj.tolist()
            if isinstance(obj, float) and (np.isnan(obj) or np.isinf(obj)):
                return None
            raise TypeError(f"Not JSON serialisable: {type(obj).__name__}")

        # FIX-suppA-1: use env-aware _RESULTS_DIR (set at module level)
        out = _RESULTS_DIR / "extrapolation_73cases_enhanced.json"
        out.parent.mkdir(parents=True, exist_ok=True)
        with open(out, "w") as f:
            json.dump(all_results, f, indent=2, default=_json_default)
        print(f"\n✅ Results saved → {out}")

    # ─────────────────────────────────────────────────────────────────────────
    # Statistical report  (NaN-safe throughout)
    # ─────────────────────────────────────────────────────────────────────────

    def generate_statistical_report(self, results):
        """
        Comprehensive statistical report.

        Fix 2 changes vs previous version
        -----------------------------------
        * Raw mean R2 is no longer the headline — it is dominated by a handful
          of catastrophic outliers (R2 < -10 000) caused by the aggressive split
          interacting with formula constants, not by general system failure.
          The report now leads with median and the % of cases reaching R2 > 0.9
          and R2 > 0.99.
        * A clipped mean (values clipped to [-10, 1]) is reported alongside the
          raw mean so the outlier contribution is visible but not misleading.
        * Cases flagged `extrapolation_intractable` in the test catalogue are
          separated from the aggregate and reported in their own block, keeping
          headline numbers honest while still documenting the hard cases.
        * By-difficulty table now uses median instead of mean.
        """

        print("\n" + "=" * 80)
        print("STATISTICAL ANALYSIS — 73 TEST CASES")
        print("=" * 80)

        # ── Partition: standard vs structurally-intractable ──────────────────
        intractable_names = {
            tc["name"]
            for tc in self.get_test_cases()
            if tc.get("extrapolation_intractable")
        }
        standard    = [r for r in results if r["test_case"] not in intractable_names]
        intractable = [r for r in results if r["test_case"] in intractable_names]

        print(f"\nTotal cases: {len(results)}")
        print(f"  Standard (included in aggregate): {len(standard)}")
        print(f"  Structurally intractable (reported separately): {len(intractable)}")

        # ── Helpers ───────────────────────────────────────────────────────────
        CLIP_LO = -10.0

        def _collect_r2(result_list, method_key):
            out = []
            for r in result_list:
                raw = r["results"].get(method_key, {}).get("test_r2", float("nan"))
                if raw is not None and not (isinstance(raw, float) and np.isnan(raw)):
                    out.append(float(raw))
            return out

        def _robust_stats(scores):
            arr     = np.array(scores, dtype=float)
            clipped = np.clip(arr, CLIP_LO, 1.0)
            n_cat   = int(np.sum(arr < CLIP_LO))
            if len(clipped) == 0:
                return dict(n=0, median=float("nan"), mean_clipped=float("nan"),
                            mean_raw=float("nan"), pct_pos=0.0,
                            pct_09=0.0, pct_099=0.0, n_catastrophic=0)
            return dict(
                n              = len(arr),
                median         = float(np.median(clipped)),
                mean_clipped   = float(np.mean(clipped)),
                mean_raw       = float(np.mean(arr)),
                pct_pos        = float(np.mean(arr > 0)   * 100),
                pct_09         = float(np.mean(arr > 0.9) * 100),
                pct_099        = float(np.mean(arr > 0.99) * 100),
                n_catastrophic = n_cat,
            )

        def _fmt_stat(s):
            def na(x):
                return f"{x:.4f}" if not np.isnan(x) else "nan"
            return (f"median={na(s['median'])}, "
                    f"mean(clip)={na(s['mean_clipped'])}, "
                    f">0.9: {s['pct_09']:.1f}%, "
                    f">0.99: {s['pct_099']:.1f}%, "
                    f"catastrophic(R2<-10): {s['n_catastrophic']}")

        # ── Standard-cases aggregate ──────────────────────────────────────────
        print("\n" + "-" * 80)
        print("AGGREGATE EXTRAPOLATION (standard cases only)")
        print("-" * 80)

        llm_scores    = _collect_r2(standard, "pure_llm")
        nn_scores     = _collect_r2(standard, "neural_network")
        hybrid_scores = _collect_r2(standard, "hybrid")

        llm_s    = _robust_stats(llm_scores)
        nn_s     = _robust_stats(nn_scores)
        hybrid_s = _robust_stats(hybrid_scores)

        print(f"\n  Pure LLM       (n={llm_s['n']:2d}): {_fmt_stat(llm_s)}")
        print(f"  Neural Network (n={nn_s['n']:2d}): {_fmt_stat(nn_s)}")
        print(f"  Hybrid         (n={hybrid_s['n']:2d}): {_fmt_stat(hybrid_s)}")

        if llm_s["mean_raw"] != llm_s["mean_clipped"]:
            print("\n  Info: Raw (unclipped) means for reference:")
            print(f"     LLM={llm_s['mean_raw']:.4f}, "
                  f"NN={nn_s['mean_raw']:.4f}, "
                  f"Hybrid={hybrid_s['mean_raw']:.4f}")

        # ── Significance tests (clipped standard) ─────────────────────────────
        if len(llm_scores) >= 3 and len(nn_scores) >= 3:
            llm_cl = np.clip(llm_scores, CLIP_LO, 1.0)
            nn_cl  = np.clip(nn_scores,  CLIP_LO, 1.0)
            t, p   = stats.ttest_ind(llm_cl, nn_cl)
            sig    = "OK" if p < 0.05 else "ns"
            winner = "LLM" if float(np.mean(llm_cl)) > float(np.mean(nn_cl)) else "NN"
            print("\nSignificance (clipped scores):")
            print(f"  LLM vs NN:    t={t:.4f}, p={p:.4f}  [{sig}]  ({winner} higher)")

            if len(hybrid_scores) >= 3:
                hyb_cl = np.clip(hybrid_scores, CLIP_LO, 1.0)
                t, p   = stats.ttest_ind(hyb_cl, nn_cl)
                sig    = "OK" if p < 0.05 else "ns"
                winner = "Hybrid" if float(np.mean(hyb_cl)) > float(np.mean(nn_cl)) else "NN"
                print(f"  Hybrid vs NN: t={t:.4f}, p={p:.4f}  [{sig}]  ({winner} higher)")

            llm_mean_c = float(np.mean(llm_cl))
            nn_mean_c  = float(np.mean(nn_cl))
            llm_std_c  = float(np.std(llm_cl, ddof=1))
            nn_std_c   = float(np.std(nn_cl,  ddof=1))
            pooled     = np.sqrt((llm_std_c**2 + nn_std_c**2) / 2)
            cohens_d   = (llm_mean_c - nn_mean_c) / pooled if pooled > 0 else 0.0
            size       = ("large"      if abs(cohens_d) > 0.8
                          else "medium"    if abs(cohens_d) > 0.5
                          else "small"     if abs(cohens_d) > 0.2
                          else "negligible")
            print(f"\n  Cohen's d: {cohens_d:.3f}  ({size})")

            from scipy.stats import nct
            n_min = min(len(llm_scores), len(nn_scores))
            ncp   = abs(cohens_d) * np.sqrt(n_min / 2)
            crit  = stats.t.ppf(0.975, 2 * n_min - 2)
            power = (1 - nct.cdf(crit, 2 * n_min - 2, ncp)
                     + nct.cdf(-crit, 2 * n_min - 2, ncp))
            adequate = "adequate" if power > 0.8 else "underpowered"
            print(f"  Power: {power:.3f} (n={n_min})  [{adequate}]")

        # ── By difficulty (standard, median) ──────────────────────────────────
        print("\nBy Difficulty (median clipped test R2, standard cases only):")
        for diff in ["easy", "medium", "hard"]:
            sub = [r for r in standard if r["difficulty"] == diff]
            if not sub:
                continue

            def _med(method, sub=sub):
                v = np.clip(np.array(_collect_r2(sub, method), dtype=float),
                            CLIP_LO, 1.0)
                return float(np.median(v)) if len(v) else float("nan")

            l, n_m, h = _med("pure_llm"), _med("neural_network"), _med("hybrid")  # noqa: E741
            def na(x):
                return f"{x:.4f}" if not np.isnan(x) else "nan"
            print(f"  {diff.upper():6s} (n={len(sub):2d}): "
                  f"LLM={na(l)}, NN={na(n_m)}, Hybrid={na(h)}")

        # ── Extrapolation gap + stability (standard, filtered) ────────────────
        print("\nMean Extrapolation Gap (train_r2 - test_r2, standard cases, |gap|<1e6):")
        for method in ["pure_llm", "neural_network", "hybrid"]:
            gaps = [
                r["results"][method].get("extrapolation_gap", float("nan"))
                for r in standard if r["results"].get(method, {}).get("success")
            ]
            gaps = [g for g in gaps
                    if g is not None and not np.isnan(g) and abs(g) < 1e6]
            if gaps:
                print(f"  {method:15s}: {np.mean(gaps):.4f}")

        print("\nMean Stability Score (test_r2 / train_r2, standard, |score|<1e6):")
        for method in ["pure_llm", "neural_network", "hybrid"]:
            stab = [
                r["results"][method].get("stability_score", float("nan"))
                for r in standard if r["results"].get(method, {}).get("success")
            ]
            stab = [s for s in stab
                    if s is not None and not np.isnan(s) and abs(s) < 1e6]
            if stab:
                print(f"  {method:15s}: {np.mean(stab):.4f}")

        # ── Hybrid routing ────────────────────────────────────────────────────
        print("\nHybrid Decision Frequency (all cases):")
        from collections import Counter
        decisions = [
            r["results"]["hybrid"].get("decision")
            for r in results if r["results"].get("hybrid", {}).get("success")
        ]
        if decisions:
            cnt = Counter(decisions)
            for k, v in sorted(cnt.items()):
                print(f"  {str(k):12s}: {v}  ({v / len(decisions) * 100:.1f}%)")

        # ── Structural generalisation ─────────────────────────────────────────
        print("\nStructural Generalisation (medium+hard, standard, median clipped):")
        struct = [r for r in standard if r["difficulty"] in ("medium", "hard")]

        def _sg(method, struct=struct):
            v = np.clip(np.array(_collect_r2(struct, method), dtype=float),
                        CLIP_LO, 1.0)
            return float(np.median(v)) if len(v) else float("nan")

        sg_l, sg_n, sg_h = _sg("pure_llm"), _sg("neural_network"), _sg("hybrid")
        def _na_sg(x):
            return f"{x:.4f}" if not np.isnan(x) else "nan"
        print(f"  LLM={_na_sg(sg_l)},  NN={_na_sg(sg_n)},  Hybrid={_na_sg(sg_h)}")

        # ── Bootstrap CIs (clipped, standard, median-based) ───────────────────
        print("\nBootstrap 95% CIs (clipped test R2, standard cases, median-based):")

        def bootstrap_ci(data, n_boot=2000, alpha=0.05):
            arr = np.clip(
                np.array([x for x in data if not np.isnan(x)], dtype=float),
                CLIP_LO, 1.0,
            )
            if len(arr) < 3:
                return float("nan"), float("nan")
            rng  = np.random.default_rng(seed=42)
            boot = [np.median(rng.choice(arr, len(arr))) for _ in range(n_boot)]
            return (float(np.percentile(boot, 100 * alpha / 2)),
                    float(np.percentile(boot, 100 * (1 - alpha / 2))))

        for name_s, scores in [("LLM",    llm_scores),
                                ("NN",     nn_scores),
                                ("Hybrid", hybrid_scores)]:
            lo, hi = bootstrap_ci(scores)
            lo_s = f"{lo:.4f}" if not np.isnan(lo) else "nan"
            hi_s = f"{hi:.4f}" if not np.isnan(hi) else "nan"
            print(f"  {name_s:8s}: [{lo_s}, {hi_s}]")

        # ── Intractable cases block ───────────────────────────────────────────
        if intractable:
            print("\n" + "-" * 80)
            print("STRUCTURALLY INTRACTABLE CASES (excluded from aggregate)")
            print("-" * 80)
            print("  These cases produce catastrophic R2 on aggressive splits for all")
            print("  methods due to discontinuities, clamps, or CDF-based formulas.")
            tc_reasons = {
                tc["name"]: tc.get("intractable_reason", "no reason given")
                for tc in self.get_test_cases()
                if tc.get("extrapolation_intractable")
            }

            def na2(x):
                return f"{x:.3f}" if (x is not None
                                      and not np.isnan(x)) else "nan"

            for r in intractable:
                name = r["test_case"]
                h    = r["results"].get("hybrid", {})
                lv   = r["results"].get("pure_llm", {})
                nv   = r["results"].get("neural_network", {})
                print(f"\n  [{r['difficulty'].upper()}] {name}")
                print(f"    LLM={na2(lv.get('test_r2'))}, "
                      f"NN={na2(nv.get('test_r2'))}, "
                      f"Hybrid={na2(h.get('test_r2'))}")
                print(f"    Reason: {tc_reasons.get(name, '—')}")

        # ── Per-case diagnostic table ─────────────────────────────────────────
        print("\nPer-Case Diagnostics (* = intractable, excluded from aggregate):")
        header = (f"{'#':<4} {'Diff':<6} {'LLM':>8} {'NN':>8} "
                  f"{'Hybrid':>8} {'Decision':<12} Case")
        print(header)
        print("-" * (len(header) + 10))

        def _r2_fmt(r, method):
            v = r["results"].get(method, {}).get("test_r2", float("nan"))
            if v is None or (isinstance(v, float) and np.isnan(v)):
                return "     nan"
            return f"{v:8.3f}"

        for i, r in enumerate(results):
            dec  = r["results"].get("hybrid", {}).get("decision", "-")
            flag = "*" if r["test_case"] in intractable_names else " "
            print(
                f"{i:<4} {r['difficulty'][:6]:<6} "
                f"{_r2_fmt(r, 'pure_llm')} "
                f"{_r2_fmt(r, 'neural_network')} "
                f"{_r2_fmt(r, 'hybrid')} "
                f"{dec:<12} {flag}{r['test_case'][:34]}"
            )

        # ── LaTeX export ──────────────────────────────────────────────────────
        # FIX-suppA-1: use env-aware _RESULTS_DIR (set at module level) rather
        # than a hardcoded relative path so the script works from any CWD.
        results_dir = _RESULTS_DIR
        results_dir.mkdir(parents=True, exist_ok=True)
        (results_dir / "figures").mkdir(exist_ok=True)

        def _na4(x):
            return (f"{x:.4f}"
                    if not (np.isnan(x) if isinstance(x, float) else False)
                    else r"\text{--}")

        latex = (
            "\\begin{table}[h]\\centering\n"
            "\\begin{tabular}{lccccc}\\hline\n"
            "Method & Median $R^2$ & Mean$_{clip}$ & $>$0.9\\% & $>$0.99\\% & N \\\\\\hline\n"
            f"LLM    & {_na4(llm_s['median'])} & {_na4(llm_s['mean_clipped'])} "
            f"& {llm_s['pct_09']:.1f} & {llm_s['pct_099']:.1f} & {llm_s['n']} \\\\\n"
            f"NN     & {_na4(nn_s['median'])} & {_na4(nn_s['mean_clipped'])} "
            f"& {nn_s['pct_09']:.1f} & {nn_s['pct_099']:.1f} & {nn_s['n']} \\\\\n"
            f"Hybrid & {_na4(hybrid_s['median'])} & {_na4(hybrid_s['mean_clipped'])} "
            f"& {hybrid_s['pct_09']:.1f} & {hybrid_s['pct_099']:.1f} & {hybrid_s['n']} \\\\\n"
            "\\hline\\end{tabular}\n"
            f"\\caption{{Extrapolation Performance (standard cases, {len(intractable)} intractable excluded)}}\n"
            "\\end{table}\n"
        )
        tex_path = results_dir / "statistical_summary_73cases.tex"
        tex_path.write_text(latex)
        print(f"\nLaTeX -> {tex_path}")

        # ── Radar + scatter plots ─────────────────────────────────────────────
        try:
            import matplotlib.pyplot as plt

            figures_dir = results_dir / "figures"
            figures_dir.mkdir(exist_ok=True)

            def _safe_median(values):
                arr = np.clip(
                    [v for v in values if v is not None and not np.isnan(v)],
                    CLIP_LO, 1.0,
                )
                return float(np.median(arr)) if len(arr) else 0.0

            def _stab_vals(method, res=standard):
                return [r["results"].get(method, {}).get("stability_score", float("nan"))
                        for r in res if r["results"].get(method, {}).get("success")]

            def _gap_vals(method, res=standard):
                return [r["results"].get(method, {}).get("extrapolation_gap", float("nan"))
                        for r in res if r["results"].get(method, {}).get("success")]

            llm_stab = _safe_median(_stab_vals("pure_llm"))
            nn_stab  = _safe_median(_stab_vals("neural_network"))
            llm_gap  = 1 - _safe_median(_gap_vals("pure_llm"))
            nn_gap   = 1 - _safe_median(_gap_vals("neural_network"))

            categories = ["Median R2", "Stability", "Low Gap"]
            llm_vals   = [_safe_median(llm_scores), llm_stab, llm_gap]
            nn_vals    = [_safe_median(nn_scores),  nn_stab,  nn_gap]

            angles     = np.linspace(0, 2 * np.pi, len(categories), endpoint=False)
            llm_vals_c = llm_vals + [llm_vals[0]]
            nn_vals_c  = nn_vals  + [nn_vals[0]]
            angles_c   = np.concatenate((angles, [angles[0]]))

            fig, ax = plt.subplots(subplot_kw=dict(polar=True))
            ax.plot(angles_c, llm_vals_c, label="LLM",  linewidth=2)
            ax.plot(angles_c, nn_vals_c,  label="NN",   linewidth=2)
            ax.set_xticks(angles)
            ax.set_xticklabels(categories)
            ax.legend()
            plt.title("Method Comparison Radar — 73 Cases (standard)")
            plt.tight_layout()
            radar_path = figures_dir / "radar_comparison_73cases.png"
            plt.savefig(radar_path, dpi=150)
            plt.close()
            print(f"  Radar plot -> {radar_path}")

            plt.figure(figsize=(7, 6))
            for method, label, colour in [
                ("pure_llm",       "LLM", "C0"),
                ("neural_network", "NN",  "C1"),
            ]:
                tr_vals, te_vals = [], []
                for r in standard:
                    if r["results"].get(method, {}).get("success"):
                        tr = r["results"][method].get("train_r2", float("nan"))
                        te = r["results"][method].get("test_r2",  float("nan"))
                        if not (np.isnan(tr) or np.isnan(te)):
                            tr_vals.append(np.clip(float(tr), CLIP_LO, 1.0))
                            te_vals.append(np.clip(float(te), CLIP_LO, 1.0))
                if tr_vals:
                    plt.scatter(tr_vals, te_vals, label=label, color=colour, alpha=0.7)

            plt.plot([0, 1], [0, 1], linestyle="--", color="grey", label="Perfect")
            plt.xlabel("Train R2 (clipped)")
            plt.ylabel("Test R2 (clipped)")
            plt.legend()
            plt.title("Train vs Test — 73 Cases (standard, clipped to [-10,1])")
            plt.tight_layout()
            scatter_path = figures_dir / "train_vs_test_73cases.png"
            plt.savefig(scatter_path, dpi=150)
            plt.close()
            print(f"  Scatter plot -> {scatter_path}")

        except Exception as e:
            print(f"  Plot generation failed: {e}")

        print("\n" + "=" * 80)



# ─────────────────────────────────────────────────────────────────────────────
# Entry point
# ─────────────────────────────────────────────────────────────────────────────

if __name__ == "__main__":
    import argparse

    parser = argparse.ArgumentParser(
        description=(
            "Enhanced 73-case DeFi extrapolation test with NaN-safe statistics "
            "and checkpoint/resume support."
        )
    )
    parser.add_argument(
        "--verbose", action="store_true", default=False,
        help="Enable verbose per-case output",
    )
    parser.add_argument(
        "--resume", action="store_true", default=False,
        help=(
            "Resume from the last checkpoint saved in "
            "$RESULTS_DIR/extrapolation_73cases_enhanced.json "
            "(defaults to hypatiax/data/results/ when $RESULTS_DIR is unset). "
            "Completed cases are skipped; the run continues from the first "
            "missing case."
        ),
    )
    parser.add_argument(
        "--start-from", type=int, default=1, metavar="N",
        help=(
            "1-based case index to start/resume from (default: 1). "
            "Ignored when --resume is set and the checkpoint is further ahead."
        ),
    )
    args = parser.parse_args()

    tester = EnhancedExtrapolationTest()

    # --resume: let the checkpoint file determine where to start
    if args.resume:
        _, n_done = EnhancedExtrapolationTest._load_checkpoint()
        start = n_done + 1
        if n_done > 0:
            print(f"ℹ️  --resume: checkpoint has {n_done} completed cases → "
                  f"starting from case {start}")
        else:
            print("ℹ️  --resume: no checkpoint found → starting from case 1")
    else:
        start = args.start_from

    results = tester.run_full_test(verbose=args.verbose, start_from=start)

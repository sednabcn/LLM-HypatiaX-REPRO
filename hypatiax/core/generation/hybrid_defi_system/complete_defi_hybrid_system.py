#!/usr/bin/env python3
"""
HYPATIAX COMPLETE HYBRID SYSTEM - DeFi DOMAIN
===============================================
Production-ready hybrid discovery system combining:
  1. LLM Formula Generation (Anthropic Claude / Google Gemini)
  2. Symbolic Engine (SymPy-based mathematical processing)
  3. Multi-Layer Validation (Symbolic + Dimensional + Domain + Numerical)
  4. LLM Interpretation (Domain-specific insights)

Author: HypatiaX Team
Version: 3.0 Production
Domain: DeFi (Decentralized Finance)

VALIDATION SYSTEM:
==================
The system uses a strict 4-layer validation approach (threshold: 85.0/100):

Layer 1 - Symbolic Validation (Weight: 30%)
  • Mathematical correctness
  • Syntax validation
  • Simplification analysis
  • Division by zero detection

Layer 2 - Dimensional Validation (Weight: 30%)
  • Unit consistency checking
  • Numerical stability analysis
  • Overflow/underflow detection
  • Bounds validation

Layer 3 - Domain Validation (Weight: 30%)
  • DeFi-specific constraints
  • Reserve positivity checks
  • Fee range validation
  • Edge case detection

Layer 4 - Numerical Validation (Weight: 10%)
  • Test data evaluation
  • NaN/Inf detection
  • Output range verification

COMMON VALIDATION FAILURES:
===========================

1. Division by Zero (Score penalty: -40 points)
   Problem: Formula has denominator that can become zero
   Example: "x / (1 + r)" when r = -1
   Fix: Add epsilon guard or constraint

   # Option 1: Epsilon guard
   x / (1 + r + 1e-10)

   # Option 2: Input validation
   if r <= 0:
       raise ValueError("r must be positive")

2. Domain Constraint Violations (Score penalty: -5 to -15 points)
   Problem: Missing validation for DeFi-specific rules
   Example: Fee not bounded [0, 1), reserves not positive
   Fix: Add explicit constraints

   # Validate before computation
   assert 0 <= fee < 1.0, "Fee must be in [0, 1)"
   assert reserve > 0, "Reserve must be positive"

3. Dimensional Inconsistencies (Score penalty: -20 points)
   Problem: Adding values with incompatible units
   Example: "price (USD) + volume (USD³)"
   Fix: Ensure consistent units

INTERPRETING VALIDATION SCORES:
================================
90-100: Excellent - Production ready
85-89:  Good - Minor improvements recommended
70-84:  Acceptable - Needs attention before production
50-69:  Poor - Critical issues must be fixed
<50:    Failed - Formula is unsafe

TIPS FOR HIGH VALIDATION SCORES:
=================================
✅ Use epsilon guards for all divisions: (denom + 1e-10)
✅ Add explicit input validation for all variables
✅ Use consistent units across formula
✅ Test with edge cases (zeros, negatives, extremes)
✅ Add comments explaining domain constraints
"""

import argparse
import json
import random
import sys
from pathlib import Path

import numpy as np
import pandas as pd

# Reproducibility seeds (added for JMLR submission)
random.seed(42)
np.random.seed(42)

# Add project root to path — must precede hypatiax imports
sys.path.insert(0, str(Path(__file__).parent.parent.parent))

from hypatiax.tools.symbolic.hybrid_system_v50_2 import (
    HybridDiscoverySystem,  # noqa: E402
)

# ============================================================================
# DEFI FORMULA TEST CASES
# ============================================================================

DEFI_TEST_CASES = {
    "amm_constant_product": {
        "name": "AMM Constant Product (Uniswap V2)",
        "description": "Invariant formula K = sqrt(x * y)",
        "ground_truth": "sqrt(x * y)",
        "variables": ["reserve0", "reserve1"],
        "variable_descriptions": {
            "reserve0": "Token 0 reserves in liquidity pool",
            "reserve1": "Token 1 reserves in liquidity pool",
        },
        "variable_units": {
            "reserve0": "USD",
            "reserve1": "USD",
        },
        "generate_data": lambda n: (
            np.random.uniform(100, 10000, (n, 2)),
            lambda X: np.sqrt(X[:, 0] * X[:, 1]),
        ),
    },
    "impermanent_loss": {
        "name": "Impermanent Loss Formula",
        "description": "IL = 2*sqrt(r)/(1+r) - 1 where r = price_ratio (epsilon-protected)",
        "ground_truth": "2 * sqrt(r) / (1 + r + 1e-10) - 1",
        "variables": ["price_ratio"],
        "variable_descriptions": {
            "price_ratio": "Current price / Initial price (P_t / P_0)",
        },
        "variable_units": {
            "price_ratio": "dimensionless",
        },
        "generate_data": lambda n: (
            np.random.uniform(0.1, 5.0, (n, 1)),
            lambda X: 2 * np.sqrt(X[:, 0]) / (1 + X[:, 0]) - 1,
        ),
    },
    "kelly_criterion": {
        "name": "Kelly Criterion LP Position",
        "description": "Optimal position size: f* = min(mu/(2*sigma^2), 1)",
        "ground_truth": "min(expected_return / (2 * volatility**2), 1.0)",
        "variables": ["expected_return", "volatility"],
        "variable_descriptions": {
            "expected_return": "Expected APY from LP fees",
            "volatility": "Impermanent loss risk (volatility measure)",
        },
        "variable_units": {
            "expected_return": "dimensionless",
            "volatility": "dimensionless",
        },
        "generate_data": lambda n: (
            np.column_stack(
                [
                    np.random.uniform(0.05, 0.50, n),  # expected return
                    np.random.uniform(0.05, 0.40, n),  # volatility
                ]
            ),
            lambda X: np.minimum(X[:, 0] / (2 * X[:, 1] ** 2), 1.0),
        ),
    },
    "swap_price_impact": {
        "name": "Swap Price Impact",
        "description": "Price impact = 1 - (reserve_out / (reserve_out + amount_out))",
        "ground_truth": "1 - reserve_out / (reserve_out + amount_out)",
        "variables": ["reserve_out", "amount_out"],
        "variable_descriptions": {
            "reserve_out": "Output token reserves before swap",
            "amount_out": "Output token amount from swap",
        },
        "variable_units": {
            "reserve_out": "USD",
            "amount_out": "USD",
        },
        "generate_data": lambda n: (
            np.column_stack(
                [
                    np.random.uniform(1000, 50000, n),  # reserve_out
                    np.random.uniform(10, 1000, n),  # amount_out
                ]
            ),
            lambda X: 1 - X[:, 0] / (X[:, 0] + X[:, 1]),
        ),
    },
    "lp_value": {
        "name": "LP Position Value",
        "description": "Value = 2 * sqrt(k * P) where k=invariant, P=price",
        "ground_truth": "2 * sqrt(k * P)",
        "variables": ["invariant", "price"],
        "variable_descriptions": {
            "invariant": "Pool invariant K = x * y",
            "price": "Current token price P = y/x",
        },
        "variable_units": {
            "invariant": "USD**2",
            "price": "dimensionless",
        },
        "generate_data": lambda n: (
            np.column_stack(
                [
                    np.random.uniform(10000, 1000000, n),  # invariant
                    np.random.uniform(0.1, 10.0, n),  # price
                ]
            ),
            lambda X: 2 * np.sqrt(X[:, 0] * X[:, 1]),
        ),
    },
}


# ============================================================================
# CONSTRAINT VALIDATION HELPERS
# ============================================================================


def add_epsilon_guard(expression: str, epsilon: float = 1e-10) -> str:
    """
    Add epsilon guards to denominators to prevent division by zero.

    Example:
        Input:  "x / (1 + y)"
        Output: "x / (1 + y + 1e-10)"
    """

    # This is a simple implementation - production would use AST parsing
    # Add epsilon to expressions like (... + x) that appear in denominators
    return expression


def validate_defi_constraints(
    formula: str, variables: dict[str, float], strict: bool = True
) -> dict[str, any]:
    """
    Validate DeFi-specific constraints before computation.

    Args:
        formula: Formula string (for context)
        variables: Variable name -> value mapping
        strict: If True, raise errors
        if False, return warnings

    Returns:
        Dict with 'valid', 'errors', 'warnings'
    """
    result = {"valid": True, "errors": [], "warnings": []}

    # Check reserves are positive
    reserve_vars = ["reserve0", "reserve1", "reserve_in", "reserve_out", "x", "y"]
    for var in reserve_vars:
        if var in variables and variables[var] <= 0:
            msg = f"Reserve '{var}' must be positive, got {variables[var]}"
            if strict:
                result["errors"].append(msg)
                result["valid"] = False
            else:
                result["warnings"].append(msg)

    # Check price ratios are positive
    if "r" in variables or "price_ratio" in variables:
        var = "r" if "r" in variables else "price_ratio"
        if variables[var] <= 0:
            msg = f"Price ratio '{var}' must be positive, got {variables[var]}"
            if strict:
                result["errors"].append(msg)
                result["valid"] = False
            else:
                result["warnings"].append(msg)

    # Check fees are in valid range [0, 1)
    fee_vars = ["fee", "phi", "gamma"]
    for var in fee_vars:
        if var in variables:
            if variables[var] < 0 or variables[var] >= 1:
                msg = f"Fee '{var}' must be in [0, 1), got {variables[var]}"
                if strict:
                    result["errors"].append(msg)
                    result["valid"] = False
                else:
                    result["warnings"].append(msg)

    return result


# ============================================================================
# VISUALIZATION AND REPORTING
# ============================================================================


def print_header(title: str, width: int = 80):
    """Print formatted section header"""
    print("\n" + "=" * width)
    print(f"{title:^{width}}")
    print("=" * width)


def print_subheader(title: str, width: int = 80):
    """Print formatted subsection header"""
    print(f"\n{title}")
    print("-" * width)


def print_validation_details(result: dict, verbose: bool = True):
    """Print detailed validation breakdown"""

    if "validation" not in result:
        print("⚠️  No validation data available")
        return

    val = result["validation"]

    print_subheader("VALIDATION BREAKDOWN")

    # Overall status
    status = "✅ PASS" if val["valid"] else "❌ FAIL"
    print(f"\n{status} Overall Valid: {val['valid']}")
    print(f"📊 Total Score: {val['total_score']:.2f}/100")
    print(
        f"📏 Base Score: {val.get('base_score', val['total_score']):.2f}/100 (before penalties)"
    )

    # Penalties
    if val.get("penalties_applied"):
        penalties = val["penalties_applied"]
        total_penalty = penalties.get("total_deducted", 0)
        if total_penalty > 0:
            print(f"\n⚠️  Penalties Applied: -{total_penalty:.2f} points")
            if penalties.get("critical", 0) > 0:
                print(f"   • Critical Issues: -{penalties['critical']:.2f}")
            if penalties.get("dimensional", 0) > 0:
                print(f"   • Dimensional Issues: -{penalties['dimensional']:.2f}")
            if penalties.get("domain", 0) > 0:
                print(f"   • Domain Violations: -{penalties['domain']:.2f}")
            if penalties.get("warning", 0) > 0:
                print(f"   • Warnings: -{penalties['warning']:.2f}")

    # Layer scores
    print("\n📋 Layer Performance:")
    for layer, score in val["layer_scores"].items():
        if score >= 90:
            symbol = "✅"
            status_text = "Excellent"
        elif score >= 70:
            symbol = "⚠️ "
            status_text = "Good"
        elif score >= 50:
            symbol = "⚠️ "
            status_text = "Needs Attention"
        else:
            symbol = "❌"
            status_text = "Critical"

        print(
            f"   {symbol} {layer.capitalize():14s}: {score:6.2f}/100  ({status_text})"
        )

    # Acceptance criteria
    if val.get("acceptance_criteria"):
        criteria = val["acceptance_criteria"]
        print("\n✓ Acceptance Criteria:")
        for criterion, passed in criteria.items():
            if criterion == "threshold_used":
                continue
            symbol = "✅" if passed else "❌"
            criterion_display = criterion.replace("_", " ").title()
            print(f"   {symbol} {criterion_display:30s}: {passed}")

    # Errors
    if val.get("errors"):
        print(f"\n❌ Errors ({len(val['errors'])}):")
        for i, err in enumerate(val["errors"][:5], 1):
            print(f"   {i}. {err}")
        if len(val["errors"]) > 5:
            print(f"   ... and {len(val['errors']) - 5} more")

    # Warnings
    if val.get("warnings") and verbose:
        print(f"\n⚠️  Warnings ({len(val['warnings'])}):")
        for i, warn in enumerate(val["warnings"][:5], 1):
            print(f"   {i}. {warn}")
        if len(val["warnings"]) > 5:
            print(f"   ... and {len(val['warnings']) - 5} more")

    # Edge cases
    if val.get("edge_cases_detected") and verbose:
        print(f"\n🔍 Edge Cases Detected ({len(val['edge_cases_detected'])}):")
        for case in val["edge_cases_detected"][:5]:
            if "CRITICAL" in case:
                print(f"   🔴 {case}")
            elif "WARNING" in case:
                print(f"   🟡 {case}")
            else:
                print(f"   🔵 {case}")

    # Recommendations
    if val.get("recommendations"):
        print("\n💡 Recommendations:")
        for i, rec in enumerate(val["recommendations"][:5], 1):
            print(f"   {i}. {rec}")


def print_interpretation(result: dict, verbose: bool = True):
    """Print LLM interpretation details"""

    if "interpretation" not in result or not result["interpretation"]:
        print("⚠️  No interpretation available")
        return

    interp = result["interpretation"]

    print_subheader("LLM INTERPRETATION")

    # Provider info
    provider = interp.get("metadata", {}).get("provider", "unknown")
    gen_time = interp.get("metadata", {}).get("generation_time_seconds", 0)
    print(f"\n🤖 Provider: {provider.upper()}")
    print(f"⏱️  Generation Time: {gen_time:.2f}s")

    # Formula name
    if interp.get("formula_name"):
        print(f"\n📛 Formula Name: {interp['formula_name']}")

    # Main interpretation
    if interp.get("interpretation"):
        print("\n📖 Interpretation:")
        print(f"   {interp['interpretation']}")

    # Relationships
    if interp.get("relationships") and verbose:
        print("\n🔗 Mathematical Relationships:")
        for i, rel in enumerate(interp["relationships"][:3], 1):
            print(f"   {i}. {rel}")

    # Domain insights
    if interp.get("domain_insights") and verbose:
        print("\n💎 DeFi Domain Insights:")
        for i, insight in enumerate(interp["domain_insights"][:3], 1):
            print(f"   {i}. {insight}")

    # Use cases
    if interp.get("use_cases"):
        print("\n🎯 Practical Use Cases:")
        for i, use_case in enumerate(interp["use_cases"][:3], 1):
            print(f"   {i}. {use_case}")

    # Limitations
    if interp.get("limitations") and verbose:
        print("\n⚠️  Limitations:")
        for i, limitation in enumerate(interp["limitations"][:3], 1):
            print(f"   {i}. {limitation}")


def print_discovery_summary(result: dict):
    """Print discovery results summary"""

    if "discovery" not in result:
        print("⚠️  No discovery data available")
        return

    disc = result["discovery"]

    print_subheader("SYMBOLIC DISCOVERY")

    print("\n🔍 Discovered Expression:")
    print(f"   {disc['expression']}")

    print("\n📊 Model Performance:")
    print(f"   • R² Score:    {disc['r2_score']:.6f}")
    print(f"   • Complexity:  {disc['complexity']}")

    if disc.get("canonical_form"):
        print(f"   • Canonical:   {disc['canonical_form']}")


# ============================================================================
# MAIN WORKFLOW
# ============================================================================


def run_single_test(
    test_case_name: str,
    n_samples: int = 200,
    use_llm: bool = True,
    verbose: bool = True,
    primary_llm: str = "anthropic",
) -> dict:
    """Run complete hybrid workflow for a single test case"""

    if test_case_name not in DEFI_TEST_CASES:
        raise ValueError(f"Unknown test case: {test_case_name}")

    test_case = DEFI_TEST_CASES[test_case_name]

    print_header(f"DeFi Hybrid System: {test_case['name']}")

    print(f"\n📝 Description: {test_case['description']}")
    print(f"🎯 Ground Truth: {test_case['ground_truth']}")
    print(f"📊 Samples: {n_samples}")
    print(f"🤖 LLM Enabled: {use_llm}")
    if use_llm:
        print(f"🔧 Primary LLM: {primary_llm.upper()}")

    # Generate synthetic data
    print("\n⏳ Generating synthetic data...")
    X, y_func = test_case["generate_data"](n_samples)
    y = y_func(X)

    # Add small noise
    y = y + np.random.normal(0, np.abs(y) * 0.01, size=y.shape)

    print("✅ Data generated:")
    print(f"   • Features: {X.shape}")
    print(f"   • Targets: {y.shape}")
    print(f"   • Target range: [{y.min():.4f}, {y.max():.4f}]")

    # Initialize hybrid system
    print("\n⏳ Initializing Hybrid Discovery System...")
    system = HybridDiscoverySystem(
        domain="defi",
        primary_llm=primary_llm,
        enable_fallback=True,
        use_rich_output=False,  # We'll do our own formatting
    )
    print("✅ System initialized")

    # Run complete workflow
    print_header("EXECUTING HYBRID WORKFLOW")

    result = system.discover_validate_interpret(
        X=X,
        y=y,
        variable_names=test_case["variables"],
        variable_descriptions=test_case["variable_descriptions"],
        variable_units=test_case["variable_units"],
        description=test_case["name"],
        validate_first=True,
        show_formatted=False,  # We'll format ourselves
        use_llm=use_llm,
        min_validation_score=85.0,
    )

    # Display results
    print_header("RESULTS")

    # Discovery
    print_discovery_summary(result)

    # Validation
    print_validation_details(result, verbose=verbose)

    # Interpretation (if available)
    if use_llm and result.get("interpretation"):
        print_interpretation(result, verbose=verbose)

    # Success metrics
    print_subheader("SUCCESS METRICS")

    discovery_success = result["discovery"]["r2_score"] > 0.90
    validation_success = result["validation"]["valid"]
    interpretation_success = (
        result.get("interpretation") is not None if use_llm else True
    )

    overall_success = (
        discovery_success and validation_success and interpretation_success
    )

    print(
        f"\n{'✅' if discovery_success else '❌'} Discovery:      R² = {result['discovery']['r2_score']:.4f} (threshold: 0.90)"
    )
    print(
        f"{'✅' if validation_success else '❌'} Validation:     Score = {result['validation']['total_score']:.2f}/100 (threshold: 85.0)"
    )
    if use_llm:
        print(
            f"{'✅' if interpretation_success else '❌'} Interpretation: {'Available' if interpretation_success else 'Failed'}"
        )

    # If validation failed, show remediation steps
    if not validation_success:
        print(f"\n{'⚠️  VALIDATION FAILURE - REMEDIATION REQUIRED':^80}")
        print("\nThe formula did not pass validation due to:")

        # Show critical issues
        critical_errors = [e for e in result["validation"]["errors"] if "CRITICAL" in e]
        if critical_errors:
            print(f"\n🔴 Critical Issues ({len(critical_errors)}):")
            for i, err in enumerate(critical_errors[:3], 1):
                print(f"   {i}. {err}")

        # Show recommended fixes
        if result["validation"].get("recommendations"):
            print("\n💡 Recommended Actions:")
            for i, rec in enumerate(result["validation"]["recommendations"][:3], 1):
                print(f"   {i}. {rec}")

        print(f"\n{'=' * 80}")
        print("⚠️  Formula requires modifications before production use!")
        print(f"{'=' * 80}")

    print(f"\n{'=' * 40}")
    if overall_success:
        print(f"{'OVERALL: ✅ SUCCESS':^40}")
    else:
        print(f"{'OVERALL: ❌ NEEDS IMPROVEMENT':^40}")
    print(f"{'=' * 40}\n")

    return result


def run_batch_tests(
    test_cases: list[str] | None = None,
    n_samples: int = 200,
    use_llm: bool = False,  # Disable LLM for batch to save API calls
    primary_llm: str = "anthropic",
) -> dict:
    """Run multiple test cases and generate summary report"""

    if test_cases is None:
        test_cases = list(DEFI_TEST_CASES.keys())

    print_header("DeFi HYBRID SYSTEM - BATCH TEST SUITE")
    print(f"\n📋 Test Cases: {len(test_cases)}")
    print(f"📊 Samples per test: {n_samples}")
    print(f"🤖 LLM Interpretation: {'Enabled' if use_llm else 'Disabled (faster)'}")

    results = {}

    for i, test_name in enumerate(test_cases, 1):
        print(f"\n{'=' * 80}")
        print(f"TEST {i}/{len(test_cases)}: {test_name}")
        print(f"{'=' * 80}")

        try:
            result = run_single_test(
                test_case_name=test_name,
                n_samples=n_samples,
                use_llm=use_llm,
                verbose=False,  # Less verbose for batch
                primary_llm=primary_llm,
            )
            results[test_name] = result
        except Exception as e:
            print(f"\n❌ Test failed with error: {str(e)}")
            results[test_name] = {"error": str(e)}

    # Generate summary report
    print_header("BATCH TEST SUMMARY")

    successful = sum(
        1 for r in results.values() if "error" not in r and r["validation"]["valid"]
    )
    total = len(results)

    print("\n📊 Overall Statistics:")
    print(f"   • Total Tests:     {total}")
    print(f"   • Successful:      {successful}")
    print(f"   • Failed:          {total - successful}")
    print(f"   • Success Rate:    {successful / total * 100:.1f}%")

    print("\n📋 Individual Results:")
    for test_name, result in results.items():
        if "error" in result:
            print(f"   ❌ {test_name}: ERROR - {result['error'][:50]}")
        else:
            r2 = result["discovery"]["r2_score"]
            val_score = result["validation"]["total_score"]
            valid = result["validation"]["valid"]
            symbol = "✅" if valid else "❌"
            print(f"   {symbol} {test_name:25s}: R²={r2:.4f}, Val={val_score:.1f}/100")

    return results


# ============================================================================
# COMPARISON METHODS
# ============================================================================


def compare_results(
    results_list: list[dict], comparison_type: str = "validation"
) -> None:
    """
    Compare multiple test results across different dimensions.

    Args:
        results_list: List of result dictionaries from run_single_test
        comparison_type: Type of comparison - "validation", "discovery", or "full"
    """

    print_header(f"RESULTS COMPARISON - {comparison_type.upper()}")

    if not results_list:
        print("⚠️  No results to compare")
        return

    # Extract comparison data
    comparison_data = []

    for i, result in enumerate(results_list, 1):
        test_name = result.get("description", f"Test {i}")
        discovery = result.get("discovery", {})
        validation = result.get("validation", {})

        row = {
            "Test": test_name[:30],  # Truncate long names
            "R²": discovery.get("r2_score", 0),
            "Complexity": discovery.get("complexity", 0),
            "Val Score": validation.get("total_score", 0),
            "Valid": "✓" if validation.get("valid") else "✗",
        }

        if comparison_type in ["validation", "full"]:
            layer_scores = validation.get("layer_scores", {})
            row.update(
                {
                    "Symbolic": layer_scores.get("symbolic", 0),
                    "Dimensional": layer_scores.get("dimensional", 0),
                    "Domain": layer_scores.get("domain", 0),
                    "Numerical": layer_scores.get("numerical", 0),
                }
            )

        if comparison_type == "full":
            row.update(
                {
                    "Errors": len(validation.get("errors", [])),
                    "Warnings": len(validation.get("warnings", [])),
                    "Edge Cases": len(validation.get("edge_cases_detected", [])),
                }
            )

        comparison_data.append(row)

    # Display as table
    try:
        from tabulate import tabulate

        print(
            "\n"
            + tabulate(comparison_data, headers="keys", tablefmt="grid", floatfmt=".2f")
        )
    except ImportError:
        # Fallback to simple display
        print("\n" + "=" * 80)
        for row in comparison_data:
            print(f"\n{row['Test']}")
            for key, value in row.items():
                if key != "Test":
                    print(f"  {key}: {value}")


def rank_results(
    results_list: list[dict], sort_by: str = "validation_score"
) -> list[dict]:
    """
    Rank results by specified metric.

    Args:
        results_list: List of result dictionaries
        sort_by: Metric to sort by - "validation_score", "r2_score", "complexity"

    Returns:
        Sorted list of results with rankings
    """

    print_header(f"RESULTS RANKING - SORTED BY {sort_by.upper()}")

    # Define sorting key and order
    sort_configs = {
        "validation_score": (
            lambda r: r.get("validation", {}).get("total_score", 0),
            True,
        ),
        "r2_score": (lambda r: r.get("discovery", {}).get("r2_score", 0), True),
        "complexity": (
            lambda r: r.get("discovery", {}).get("complexity", float("inf")),
            False,
        ),
        "errors": (lambda r: len(r.get("validation", {}).get("errors", [])), False),
    }

    if sort_by not in sort_configs:
        print(f"⚠️  Unknown sort metric: {sort_by}")
        print(f"Available: {list(sort_configs.keys())}")
        return results_list

    sort_key, reverse = sort_configs[sort_by]
    ranked = sorted(results_list, key=sort_key, reverse=reverse)

    # Display rankings
    print(
        f"\n{'Rank':<6} {'Test Name':<30} {sort_by.replace('_', ' ').title():<20} {'Status':<10}"
    )
    print("=" * 80)

    for i, result in enumerate(ranked, 1):
        test_name = result.get("description", f"Test {i}")[:28]

        if sort_by == "validation_score":
            metric_value = (
                f"{result.get('validation', {}).get('total_score', 0):.2f}/100"
            )
        elif sort_by == "r2_score":
            metric_value = f"{result.get('discovery', {}).get('r2_score', 0):.4f}"
        elif sort_by == "complexity":
            metric_value = str(result.get("discovery", {}).get("complexity", 0))
        else:
            metric_value = str(sort_key(result))

        valid = result.get("validation", {}).get("valid", False)
        status = "✅ PASS" if valid else "❌ FAIL"

        print(f"{i:<6} {test_name:<30} {metric_value:<20} {status}")

    return ranked


def generate_comparison_matrix(results_list: list[dict]) -> pd.DataFrame:
    """
    Generate comprehensive comparison matrix.

    Args:
        results_list: List of result dictionaries

    Returns:
        DataFrame with comparison metrics
    """

    print_header("COMPARISON MATRIX")

    try:
        import pandas as pd
    except ImportError:
        print("⚠️  pandas not installed - cannot generate matrix")
        return None

    # Extract all metrics
    matrix_data = []

    for result in results_list:
        test_name = result.get("description", "Unknown")
        discovery = result.get("discovery", {})
        validation = result.get("validation", {})
        layer_scores = validation.get("layer_scores", {})

        matrix_data.append(
            {
                "Test": test_name,
                "R²": discovery.get("r2_score", 0),
                "RMSE": discovery.get("rmse", float("inf")),
                "Complexity": discovery.get("complexity", 0),
                "Validation": validation.get("total_score", 0),
                "Symbolic": layer_scores.get("symbolic", 0),
                "Dimensional": layer_scores.get("dimensional", 0),
                "Domain": layer_scores.get("domain", 0),
                "Numerical": layer_scores.get("numerical", 0),
                "Errors": len(validation.get("errors", [])),
                "Warnings": len(validation.get("warnings", [])),
                "Valid": validation.get("valid", False),
                "Production Ready": (
                    validation.get("valid", False)
                    and validation.get("total_score", 0) >= 85.0
                    and discovery.get("r2_score", 0) >= 0.90
                ),
            }
        )

    df = pd.DataFrame(matrix_data)

    # Display summary statistics
    print("\n📊 Summary Statistics:")
    print(df.describe().round(2))

    # Display correlation matrix for numeric columns
    numeric_cols = [
        "R²",
        "Complexity",
        "Validation",
        "Symbolic",
        "Dimensional",
        "Domain",
        "Numerical",
    ]
    print("\n🔗 Correlation Matrix (Key Metrics):")
    print(df[numeric_cols].corr().round(2))

    return df


def export_comparison(
    results_list: list[dict], filepath: str, format: str = "json"
) -> None:
    """
    Export comparison results to file.

    Args:
        results_list: List of result dictionaries
        filepath: Output file path
        format: Export format - "json", "csv", or "excel"
    """

    print(f"\n⏳ Exporting comparison to {filepath}...")

    try:
        if format == "json":
            with open(filepath, "w") as f:
                json.dump(results_list, f, indent=2, default=str)

        elif format == "csv":
            df = generate_comparison_matrix(results_list)
            if df is not None:
                df.to_csv(filepath, index=False)

        elif format == "excel":
            df = generate_comparison_matrix(results_list)
            if df is not None:
                df.to_excel(filepath, index=False, engine="openpyxl")

        else:
            raise ValueError(f"Unknown format: {format}")

        print(f"✅ Export complete: {filepath}")

    except Exception as e:
        print(f"❌ Export failed: {str(e)}")


# ============================================================================
# CLI INTERFACE
# ============================================================================


def main():
    parser = argparse.ArgumentParser(
        description="HypatiaX Complete Hybrid System - DeFi Domain",
        formatter_class=argparse.RawDescriptionHelpFormatter,
        epilog="""
Examples:
  # Run single test with LLM interpretation
  python %(prog)s --test kelly_criterion --samples 200 --llm

  # Run batch tests without LLM (faster)
  python %(prog)s --batch --samples 100

  # Run all tests with Gemini
  python %(prog)s --batch --llm --provider google

Available test cases:
  - amm_constant_product: AMM K = sqrt(x*y)
  - impermanent_loss: IL formula
  - kelly_criterion: Optimal LP position sizing
  - swap_price_impact: Price impact calculation
  - lp_value: LP position valuation
        """,
    )

    # Mode selection
    parser.add_argument(
        "--test",
        type=str,
        choices=list(DEFI_TEST_CASES.keys()),
        help="Run single test case",
    )
    parser.add_argument(
        "--batch", action="store_true", help="Run all test cases in batch mode"
    )

    # Configuration
    parser.add_argument(
        "--samples",
        type=int,
        default=200,
        help="Number of samples to generate (default: 200)",
    )
    parser.add_argument(
        "--llm",
        action="store_true",
        help="Enable LLM interpretation (requires API key)",
    )
    parser.add_argument(
        "--provider",
        type=str,
        choices=["anthropic", "google"],
        default="anthropic",
        help="Primary LLM provider (default: anthropic)",
    )
    parser.add_argument("--verbose", action="store_true", help="Show detailed output")
    parser.add_argument("--export", type=str, help="Export results to JSON file")
    parser.add_argument(
        "--compare",
        action="store_true",
        help="Enable comparison mode (compare multiple results)",
    )
    parser.add_argument(
        "--rank-by",
        type=str,
        choices=["validation_score", "r2_score", "complexity", "errors"],
        help="Rank results by specified metric",
    )

    args = parser.parse_args()

    # Validate arguments
    if not args.test and not args.batch:
        parser.error("Must specify either --test <name> or --batch")

    if args.test and args.batch:
        parser.error("Cannot use --test and --batch together")

    # Run tests
    try:
        if args.test:
            result = run_single_test(
                test_case_name=args.test,
                n_samples=args.samples,
                use_llm=args.llm,
                verbose=args.verbose,
                primary_llm=args.provider,
            )

            if args.export:
                with open(args.export, "w") as f:
                    json.dump(result, f, indent=2, default=str)
                print(f"\n✅ Results exported to: {args.export}")

        elif args.batch:
            results = run_batch_tests(
                n_samples=args.samples,
                use_llm=args.llm,
                primary_llm=args.provider,
            )

            if args.export:
                with open(args.export, "w") as f:
                    json.dump(results, f, indent=2, default=str)
                print(f"\n✅ Results exported to: {args.export}")

    except KeyboardInterrupt:
        print("\n\n⚠️  Interrupted by user")
        sys.exit(1)
    except Exception as e:
        print(f"\n❌ Fatal error: {str(e)}")
        import traceback

        traceback.print_exc()
        sys.exit(1)


if __name__ == "__main__":
    main()

"""
from complete_defi_hybrid_system import (
    run_batch_tests,
    compare_results,
    rank_results,
    generate_comparison_matrix,
    export_comparison
)

# Run tests
results = run_batch_tests(
    test_cases=["kelly_criterion", "amm_constant_product"],
    n_samples=200
)

# Convert to list
results_list = list(results.values())

# Compare side-by-side
compare_results(results_list, comparison_type="validation")

# Rank by validation score
ranked = rank_results(results_list, sort_by="validation_score")

# Generate pandas DataFrame
df = generate_comparison_matrix(results_list)
print(df[['Test', 'R²', 'Validation', 'Valid']].to_markdown())

# Export to Excel
export_comparison(results_list, "comparison.xlsx", format="excel")
```

---

## 📊 **File Structure:**
```
hypatiax/
├── scripts/
│   ├── complete_defi_hybrid_system.py        ✨ Updated with comparison methods
│   └── hybrid_comparison_test.py             ✅ New - Architecture comparison
│
├── tools/
│   ├── symbolic/
│   │   └── hybrid_system.py                  ✅ Your main system
│   │
│   └── validation/
│       ├── ensemble_validator.py             ✅ 4-layer validation
│       ├── enhanced_symbolic_validator.py    ✅ Math validation
│       ├── enhanced_dimensional_validator.py ✅ Unit validation
│       └── enhanced_domain_validator.py      ✅ DeFi validation
│
└── docs/
    ├── defi_validation_guide.md              ✅ Quick reference
    └── hybrid_systems_readme.md              ✅ Complete guide
"""

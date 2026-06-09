#!/usr/bin/env python3
"""
Lambda=0 Ablation on Real Domains + Synthetic Comparison.

Critical experiment for NeurIPS: Proves competition alone induces specialization
on REAL data, not just synthetic benchmarks.

Key hypothesis:
- λ=0 on Energy/Weather: SI > 0.40 (mechanism works when conditions met)
- λ=0 on Finance: SI < 0.35 (mechanism fails when strategy differentiation low)
- This validates the two-condition framework causally.

Statistical Framework:
- 30 trials per condition
- Bootstrap 95% CIs
- One-sample t-test against threshold
"""

import os
import sys
import json
import math
from pathlib import Path
from typing import Dict, List, Tuple
from datetime import datetime
import warnings
warnings.filterwarnings('ignore')

import numpy as np
import pandas as pd
from scipy import stats
from tqdm import tqdm

# Add parent directory to path
sys.path.insert(0, str(Path(__file__).parent.parent))

from experiments._affinity_update import eg_eta_for_regimes


def bootstrap_ci(data: np.ndarray, n_bootstrap: int = 1000,
                 confidence: float = 0.95) -> Tuple[float, float]:
    """Compute bootstrap confidence interval."""
    bootstrapped_means = []
    for _ in range(n_bootstrap):
        sample = np.random.choice(data, size=len(data), replace=True)
        bootstrapped_means.append(np.mean(sample))
    alpha = 1 - confidence
    lower = np.percentile(bootstrapped_means, alpha / 2 * 100)
    upper = np.percentile(bootstrapped_means, (1 - alpha / 2) * 100)
    return lower, upper


def cohens_d(group1: np.ndarray, group2: np.ndarray) -> float:
    """Compute Cohen's d effect size."""
    n1, n2 = len(group1), len(group2)
    var1, var2 = np.var(group1, ddof=1), np.var(group2, ddof=1)
    pooled_std = np.sqrt(((n1 - 1) * var1 + (n2 - 1) * var2) / (n1 + n2 - 2))
    if pooled_std == 0:
        return 0.0
    return (np.mean(group1) - np.mean(group2)) / pooled_std


# ==============================================================================
# Agent Classes (simplified for prediction domains)
# ==============================================================================

class PredictionAgent:
    """Agent that specializes in prediction methods for specific regimes."""

    def __init__(self, agent_id: int, methods: List[str], regimes: List[str], seed: int = None,
                 lr_override: float = None):
        self.agent_id = agent_id
        self.methods = methods
        self.regimes = regimes
        self.rng = np.random.default_rng(seed)
        # When set, use this exact EG win-step instead of the regime-count
        # rescale. Used by the learning-rate sweep (exp_lr_sweep.py).
        self.lr_override = lr_override

        # Method beliefs per regime (higher = more preferred)
        self.method_beliefs = {
            r: {m: 1.0 for m in methods} for r in regimes
        }

        # Niche affinities (which regimes this agent prefers)
        self.niche_affinities = {r: 1.0 / len(regimes) for r in regimes}

        self.wins = 0
        self.total = 0

    def select_method(self, regime: str) -> str:
        """Select method using Thompson Sampling within current regime."""
        beliefs = self.method_beliefs.get(regime, {m: 1.0 for m in self.methods})

        # Thompson Sampling: sample from Beta distributions
        samples = {}
        for method, belief in beliefs.items():
            # Use belief as alpha, with beta = 2 (slight prior towards exploration)
            alpha = max(belief, 0.1)
            beta = 2.0
            samples[method] = self.rng.beta(alpha, beta)

        return max(samples, key=samples.get)

    def update(self, regime: str, method: str, won: bool, niche_bonus: float = 0.0):
        """Update beliefs and affinities based on outcome.

        Niche affinity updates use the V4 exponentiated-gradient form:
            win:    alpha[regime] *= exp(+lr)     (+ exp(niche_bonus) if primary match)
            loss:   alpha[regime] *= exp(-lr/2)
        followed by simplex normalization. This preserves strict positivity and
        the simplex by construction, replacing the V3 additive + max(0.01, .) clamp.

        ``lr`` is rescaled per regime count to match the canonical headline
        pipeline's specialization timescale (eg_eta_for_regimes); the loss step
        keeps the original 2:1 win:loss magnitude ratio.
        """
        self.total += 1

        if won:
            self.wins += 1
            self.method_beliefs[regime][method] += 1.0
        else:
            self.method_beliefs[regime][method] = max(0.1, self.method_beliefs[regime][method] - 0.3)

        lr = self.lr_override if self.lr_override is not None else eg_eta_for_regimes(len(self.regimes))
        primary_niche = max(self.niche_affinities, key=self.niche_affinities.get)
        if won:
            self.niche_affinities[regime] *= math.exp(lr)
            if regime == primary_niche:
                self.niche_affinities[regime] *= math.exp(niche_bonus)
        else:
            self.niche_affinities[regime] *= math.exp(-lr / 2)

        total_affinity = sum(self.niche_affinities.values())
        self.niche_affinities = {r: a / total_affinity for r, a in self.niche_affinities.items()}

    def get_si(self) -> float:
        """Compute specialization index (entropy-based)."""
        affinities = np.array(list(self.niche_affinities.values()))
        affinities = affinities / (affinities.sum() + 1e-8)
        entropy = -np.sum(affinities * np.log(affinities + 1e-8))
        max_entropy = np.log(len(affinities))
        return 1 - (entropy / max_entropy) if max_entropy > 0 else 0.0


class PredictionPopulation:
    """Population of prediction agents competing across regimes."""

    def __init__(self, n_agents: int, methods: List[str], regimes: List[str],
                 niche_bonus_lambda: float = 0.5, seed: int = None,
                 lr_override: float = None):
        self.n_agents = n_agents
        self.methods = methods
        self.regimes = regimes
        self.niche_bonus_lambda = niche_bonus_lambda
        self.rng = np.random.default_rng(seed)

        self.agents = [
            PredictionAgent(i, methods, regimes, seed=seed + i if seed else None,
                            lr_override=lr_override)
            for i in range(n_agents)
        ]

        self.history = []

    def run_iteration(self, regime: str, true_value: float,
                      predict_fn) -> Dict:
        """
        Run one iteration of competition.

        Args:
            regime: Current regime label
            true_value: Ground truth value to predict
            predict_fn: Function(method_name) -> prediction
        """
        # Each agent selects a method and makes prediction
        predictions = {}
        for agent in self.agents:
            method = agent.select_method(regime)
            pred = predict_fn(method)
            error = abs(pred - true_value)
            predictions[agent.agent_id] = {
                'method': method,
                'prediction': pred,
                'error': error
            }

        # Find winner (lowest error)
        winner_id = min(predictions, key=lambda x: predictions[x]['error'])
        winner_method = predictions[winner_id]['method']

        # Update all agents
        for agent in self.agents:
            won = (agent.agent_id == winner_id)
            method = predictions[agent.agent_id]['method']

            # Apply niche bonus only if lambda > 0
            primary_niche = max(agent.niche_affinities, key=agent.niche_affinities.get)
            bonus = self.niche_bonus_lambda if (regime == primary_niche) else 0.0

            agent.update(regime, method, won, niche_bonus=bonus)

        mean_error = float(np.mean([p['error'] for p in predictions.values()]))

        self.history.append({
            'regime': regime,
            'winner_id': winner_id,
            'winner_method': winner_method,
            'winner_error': predictions[winner_id]['error'],
            'mean_error': mean_error,
        })

        return {'winner_id': winner_id, 'winner_method': winner_method}

    def get_population_si(self) -> float:
        """Get mean SI across all agents."""
        return np.mean([agent.get_si() for agent in self.agents])

    def get_agent_sis(self) -> List[float]:
        """Get SI for each agent."""
        return [agent.get_si() for agent in self.agents]


# ==============================================================================
# Domain-Specific Prediction Methods
# ==============================================================================

def get_domain_predictor(domain: str, method: str, history: np.ndarray,
                         time_idx: int = 0) -> float:
    """Get prediction for a specific domain and method."""

    if len(history) == 0:
        return 0.0

    if domain == "energy":
        if method == "PeakLoad":
            # Use 24h ago value with trend
            if len(history) >= 24:
                val_24h = history[-24]
                trend = (history[-1] - history[-3]) / 3 if len(history) >= 3 else 0
                return val_24h + trend
            return history[-1]
        elif method == "LoadTracking":
            # Exponential smoothing
            alpha = 0.3
            smoothed = history[-1]
            for v in reversed(history[-10:]):
                smoothed = alpha * v + (1 - alpha) * smoothed
            return smoothed
        elif method == "RenewableAware":
            # Average of past 3 days same hour
            if len(history) >= 24:
                same_hour = [history[-i*24] for i in range(1, 4) if len(history) >= i*24]
                if same_hour:
                    return np.mean(same_hour)
            return history[-1]

    elif domain == "weather":
        if method == "Persistence":
            return history[-1]
        elif method == "Seasonal":
            if len(history) >= 7:
                return np.mean(history[-7:])
            return history[-1]
        elif method == "StormAware":
            if len(history) >= 5:
                ma = np.mean(history[-7:]) if len(history) >= 7 else np.mean(history)
                return history[-1] + 0.4 * (ma - history[-1])
            return history[-1]

    elif domain == "finance":
        if method == "Momentum":
            if len(history) >= 5:
                return history[-1] + (history[-1] - history[-5]) * 0.5
            return history[-1]
        elif method == "MeanRevert":
            if len(history) >= 20:
                ma = np.mean(history[-20:])
                return history[-1] + 0.3 * (ma - history[-1])
            return history[-1]
        elif method == "Volatility":
            if len(history) >= 10:
                vol = np.std(history[-10:])
                return history[-1] + vol * np.random.randn() * 0.1
            return history[-1]

    # Fallback
    return history[-1]


# ==============================================================================
# Data Loading
# ==============================================================================

def load_domain_data(domain: str) -> Tuple[np.ndarray, List[str], List[str]]:
    """
    Load data for a domain and return (values, regimes, method_names).
    """
    base_path = Path(__file__).parent.parent / "data"

    if domain == "energy":
        csv_path = base_path / "energy" / "eia" / "hourly_demand.csv"
        if csv_path.exists():
            df = pd.read_csv(csv_path)
            values = df['demand'].values[:500]  # Use first 500 points
        else:
            # Generate synthetic energy data
            np.random.seed(42)
            t = np.arange(500)
            base = 1000 + 200 * np.sin(2 * np.pi * t / 24)  # Daily pattern
            noise = np.random.randn(500) * 50
            values = base + noise

        # Classify regimes based on load level
        regimes = []
        for i, v in enumerate(values):
            hour = i % 24
            if 6 <= hour <= 18 and v > np.median(values):
                regimes.append("peak_demand")
            elif v < np.percentile(values, 25):
                regimes.append("low_demand")
            elif np.std(values[max(0, i-10):i+1]) > np.std(values) * 1.5 if i > 10 else False:
                regimes.append("volatile")
            else:
                regimes.append("normal")

        methods = ["PeakLoad", "LoadTracking", "RenewableAware"]
        return values, regimes, methods

    elif domain == "weather":
        csv_path = base_path / "weather" / "noaa" / "daily_weather.csv"
        if csv_path.exists():
            df = pd.read_csv(csv_path)
            values = df['temperature'].values[:500]
        else:
            # Generate synthetic weather data
            np.random.seed(43)
            t = np.arange(500)
            base = 15 + 10 * np.sin(2 * np.pi * t / 365)  # Seasonal pattern
            noise = np.random.randn(500) * 5
            values = base + noise

        # Classify regimes
        regimes = []
        for i, v in enumerate(values):
            if v > np.percentile(values, 75):
                regimes.append("stable_warm")
            elif v < np.percentile(values, 25):
                regimes.append("stable_cold")
            elif np.std(values[max(0, i-5):i+1]) > np.std(values) * 1.5 if i > 5 else False:
                regimes.append("volatile_storm")
            else:
                regimes.append("transition")

        methods = ["Persistence", "Seasonal", "StormAware"]
        return values, regimes, methods

    elif domain == "finance":
        # Load from bybit data
        csv_path = base_path / "bybit" / "BTCUSDT_1D.csv"
        if csv_path.exists():
            df = pd.read_csv(csv_path)
            values = df['close'].values[:500]
        else:
            # Generate synthetic finance data
            np.random.seed(44)
            values = [10000]
            for _ in range(499):
                ret = np.random.randn() * 0.02
                values.append(values[-1] * (1 + ret))
            values = np.array(values)

        # Classify regimes based on returns
        regimes = []
        for i in range(len(values)):
            if i < 5:
                regimes.append("neutral")
                continue
            ret = (values[i] - values[i-5]) / values[i-5]
            vol = np.std(np.diff(values[max(0, i-20):i+1])) / values[i] if i > 20 else 0.02

            if ret > 0.05:
                regimes.append("trend_up")
            elif ret < -0.05:
                regimes.append("trend_down")
            elif vol > 0.03:
                regimes.append("volatile")
            else:
                regimes.append("mean_revert")

        methods = ["Momentum", "MeanRevert", "Volatility"]
        return values, regimes, methods

    elif domain == "synthetic":
        # Perfect synthetic environment with clear regimes
        np.random.seed(45)
        n = 500
        values = []
        regimes = []
        regime_list = ["trend_up", "trend_down", "mean_revert", "volatile"]

        for i in range(n):
            regime = regime_list[i % 4]  # Cycle through regimes
            regimes.append(regime)

            if regime == "trend_up":
                val = 100 + i * 0.5 + np.random.randn() * 2
            elif regime == "trend_down":
                val = 100 - i * 0.5 + np.random.randn() * 2
            elif regime == "mean_revert":
                val = 100 + np.random.randn() * 5
            else:  # volatile
                val = 100 + np.random.randn() * 20
            values.append(val)

        values = np.array(values)
        methods = ["Momentum", "MeanRevert", "Volatility"]
        return values, regimes, methods

    else:
        raise ValueError(f"Unknown domain: {domain}")


# ==============================================================================
# Main Experiment
# ==============================================================================

def run_lambda_experiment(domain: str, lambda_val: float, n_trials: int = 30,
                          n_iterations: int = 400, n_agents: int = 8,
                          seed: int = 42) -> Dict:
    """
    Run experiment with specific lambda value on a domain.
    """
    values, regimes, methods = load_domain_data(domain)

    si_values = []
    performance_values = []

    for trial in tqdm(range(n_trials), desc=f"{domain} λ={lambda_val}", leave=False):
        trial_seed = seed + trial * 100 + int(lambda_val * 1000)

        # Create population
        unique_regimes = list(set(regimes))
        pop = PredictionPopulation(
            n_agents=n_agents,
            methods=methods,
            regimes=unique_regimes,
            niche_bonus_lambda=lambda_val,
            seed=trial_seed
        )

        # Run iterations
        errors = []
        for it in range(min(n_iterations, len(values) - 20)):
            idx = it + 20  # Start after warmup
            regime = regimes[idx]
            true_val = values[idx]
            history = values[:idx]

            # Create predict function for this iteration
            def predict_fn(method):
                return get_domain_predictor(domain, method, history, idx)

            result = pop.run_iteration(regime, true_val, predict_fn)

            # Track best error
            errors.append(pop.history[-1]['winner_error'])

        # Record final metrics
        si_values.append(pop.get_population_si())
        performance_values.append(np.mean(errors[-100:]))  # Last 100 iterations

    # Compute statistics
    si_arr = np.array(si_values)
    perf_arr = np.array(performance_values)

    si_ci = bootstrap_ci(si_arr)

    # Test against threshold
    threshold = 0.40
    t_stat, p_val = stats.ttest_1samp(si_arr, threshold)
    p_val_one_sided = p_val / 2 if t_stat > 0 else 1 - p_val / 2

    return {
        "domain": domain,
        "lambda": lambda_val,
        "n_trials": n_trials,
        "si_mean": float(si_arr.mean()),
        "si_std": float(si_arr.std()),
        "si_ci_lower": float(si_ci[0]),
        "si_ci_upper": float(si_ci[1]),
        "si_all": [float(x) for x in si_values],  # For within-trial correlation later
        "performance_mean": float(perf_arr.mean()),
        "performance_std": float(perf_arr.std()),
        "performance_all": [float(x) for x in performance_values],
        "test_vs_040": {
            "t_statistic": float(t_stat),
            "p_value_one_sided": float(p_val_one_sided),
            "significant": bool(p_val_one_sided < 0.05)
        }
    }


def run_all_experiments(n_trials: int = 30):
    """Run λ sweep on all domains."""

    # NOTE: the "synthetic" domain was dropped. Its generator cycles the 4
    # regimes in fixed equal-frequency order with deterministic predictors, so
    # all agents tie every step and no affinity ever becomes asymmetric
    # (SI == 0 regardless of eta). It was not paper-relevant and only produced
    # a degenerate row. Real-data domains are retained.
    domains = ["energy", "weather", "finance"]
    lambda_values = [0.0, 0.25, 0.50]

    results = {
        "experiment": "lambda_zero_real",
        "date": datetime.now().isoformat(),
        "config": {
            "n_trials": n_trials,
            "lambda_values": lambda_values,
            "domains": domains
        },
        "results": {}
    }

    for domain in domains:
        print(f"\n{'='*60}")
        print(f"Running {domain.upper()}")
        print(f"{'='*60}")

        results["results"][domain] = {}

        for lambda_val in lambda_values:
            result = run_lambda_experiment(domain, lambda_val, n_trials=n_trials)
            results["results"][domain][str(lambda_val)] = result

            print(f"  λ={lambda_val:.2f}: SI={result['si_mean']:.3f} ± {result['si_std']:.3f} "
                  f"[{result['si_ci_lower']:.3f}, {result['si_ci_upper']:.3f}] "
                  f"{'✓' if result['test_vs_040']['significant'] else '✗'}")

    # Summary table
    print("\n" + "="*80)
    print("SUMMARY: λ=0 Results (Competition Only)")
    print("="*80)
    print(f"{'Domain':<12} {'λ=0 SI':>12} {'λ=0.5 SI':>12} {'> 0.40?':>10} {'Two Conditions':>20}")
    print("-"*80)

    for domain in domains:
        si_0 = results["results"][domain]["0.0"]["si_mean"]
        si_05 = results["results"][domain]["0.5"]["si_mean"]
        sig = results["results"][domain]["0.0"]["test_vs_040"]["significant"]

        conditions = {
            "energy": "Yes",
            "weather": "Yes",
            "finance": "No (strategy overlap)"
        }

        print(f"{domain:<12} {si_0:>12.3f} {si_05:>12.3f} {'✓' if sig else '✗':>10} {conditions[domain]:>20}")

    print("="*80)

    # Save results
    output_dir = Path(__file__).parent.parent / "results" / "lambda_zero_real"
    output_dir.mkdir(parents=True, exist_ok=True)

    # Save without the full si_all arrays for the main results file
    results_summary = {
        "experiment": results["experiment"],
        "date": results["date"],
        "config": results["config"],
        "results": {}
    }
    for domain in domains:
        results_summary["results"][domain] = {}
        for lv in lambda_values:
            r = results["results"][domain][str(lv)].copy()
            r.pop("si_all", None)  # Remove large array
            results_summary["results"][domain][str(lv)] = r

    with open(output_dir / "results.json", "w") as f:
        json.dump(results_summary, f, indent=2)

    # Save full results with si_all for correlation analysis
    with open(output_dir / "results_full.json", "w") as f:
        json.dump(results, f, indent=2)

    print(f"\nResults saved to {output_dir}")

    return results


if __name__ == "__main__":
    print("="*80)
    print("Lambda=0 Ablation on Real Domains")
    print("Testing: Competition alone induces specialization")
    print("="*80)

    results = run_all_experiments(n_trials=30)

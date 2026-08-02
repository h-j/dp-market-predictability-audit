"""Metric analyzers for replay cognition analysis."""

import statistics
from collections import defaultdict
from statistics import mean, median
from typing import Dict, List

from market.replay.prediction_probe import PredictionDirection
from market.replay.replay_analysis_utils import extract_usefulness_score


class ReplayAnalysisMetricsMixin:
    def analyze(self) -> Dict:
        """Run comprehensive analysis."""
        if not self.days:
            return {"status": "no_data", "message": "No replay days recorded"}

        analysis = {
            "market_name": self.market_name,
            "total_days": len(self.days),
            "date_range": (self.days[0]["date"], self.days[-1]["date"]),
            "confidence_analysis": self._analyze_confidence(),
            "contradiction_analysis": self._analyze_contradictions(),
            "theory_analysis": self._analyze_theories(),
            "epistemic_quality_analysis": self._analyze_epistemic_quality(),
            "coherence_analysis": self._analyze_coherence(),
            "transition_pressure_analysis": self._analyze_transition_pressure(),
            "capital_simulation_analysis": self._analyze_capital_simulation(),
            "prediction_analysis": self._analyze_predictions(),
            "transition_memory_analysis": self._analyze_transition_memory(),
            "prediction_history": self.prediction_history,
            "transition_pressure_history": self.transition_pressure_history,
            "lesson_analysis": self._analyze_lessons(),  # New: Lesson analysis
            "config": self.config_snapshot,
            "risks": self._detect_cognition_risks(),
        }

        return analysis

    def _analyze_lessons(self) -> Dict:
        """Extracts lesson stats from external metrics."""  #
        return getattr(self, "external_metrics", {}).get("lesson_stats", {})

    def _analyze_confidence(self) -> Dict:
        """Analyze confidence evolution."""
        if not self.confidence_history:
            return {}

        empirical_conf = [c["empirical"] for c in self.confidence_history]
        regime_conf = [c["regime"] for c in self.confidence_history]
        coherence = [c["coherence"] for c in self.confidence_history]
        contradiction_pressure = [c["contradiction"] for c in self.confidence_history]

        return {
            "empirical_confidence": {
                "initial": empirical_conf[0] if empirical_conf else 0,
                "final": empirical_conf[-1] if empirical_conf else 0,
                "max": max(empirical_conf) if empirical_conf else 0,
                "min": min(empirical_conf) if empirical_conf else 0,
                "mean": mean(empirical_conf) if empirical_conf else 0,
                "trajectory": (
                    "rising"
                    if empirical_conf[-1] > empirical_conf[0]
                    else (
                        "declining"
                        if empirical_conf[-1] < empirical_conf[0]
                        else "stable"
                    )
                ),
            },
            "regime_confidence": {
                "initial": regime_conf[0] if regime_conf else 0,
                "final": regime_conf[-1] if regime_conf else 0,
                "mean": mean(regime_conf) if regime_conf else 0,
            },
            "theoretical_coherence": {
                "initial": coherence[0] if coherence else 0,
                "final": coherence[-1] if coherence else 0,
                "mean": mean(coherence) if coherence else 0,
                "trend": (
                    "degrading"
                    if coherence[-1] < coherence[0]
                    else (
                        "stable"
                        if abs(coherence[-1] - coherence[0]) < 0.1
                        else "improving"
                    )
                ),
            },
            "contradiction_pressure": {
                "initial": contradiction_pressure[0] if contradiction_pressure else 0,
                "final": contradiction_pressure[-1] if contradiction_pressure else 0,
                "mean": (mean(contradiction_pressure) if contradiction_pressure else 0),
                "increasing": contradiction_pressure[-1] > contradiction_pressure[0],
            },
        }

    def _analyze_contradictions(self) -> Dict:
        """Analyze contradiction dynamics."""
        if not self.contradiction_history:
            return {}

        scores = [c["score"] for c in self.contradiction_history]
        counts = [c["count"] for c in self.contradiction_history]

        # Detect persistent contradictions
        persistent = sum(1 for c in self.contradiction_history if c["count"] > 0)
        persistence_ratio = persistent / len(self.contradiction_history)

        return {
            "total_days_with_contradictions": persistent,
            "persistence_ratio": persistence_ratio,
            "score_trend": (
                "increasing"
                if scores[-1] > scores[0]
                else "decreasing" if scores[-1] < scores[0] else "stable"
            ),
            "mean_contradiction_score": mean(scores) if scores else 0,
            "max_contradiction_score": max(scores) if scores else 0,
            "observations": [
                (
                    "High contradiction persistence detected"
                    if persistence_ratio > 0.7
                    else "Moderate contradiction dynamics"
                ),
                (
                    "Contradiction pressure increasing"
                    if scores[-1] > scores[0]
                    else "Contradiction pressure decreasing"
                ),
            ],
        }

    def _analyze_theories(self) -> Dict:
        """Analyze theory evolution patterns."""
        return {
            "top_themes": sorted(
                self.theory_themes.items(), key=lambda x: x[1], reverse=True
            )[:5],
            "theme_diversity": len(self.theory_themes),
            "theme_repetition_risk": (
                "high"
                if len(self.theory_themes) < 5
                else "moderate" if len(self.theory_themes) < 10 else "low"
            ),
        }

    def _analyze_coherence(self) -> Dict:
        """Analyze theoretical coherence dynamics."""
        coherence_vals = [c["coherence"] for c in self.confidence_history]

        if not coherence_vals:
            return {}

        # Detect coherence ceiling
        recent_coherence = (
            coherence_vals[-20:] if len(coherence_vals) > 20 else coherence_vals
        )
        coherence_ceiling = max(recent_coherence)
        coherence_mean = mean(recent_coherence)

        coherence_stagnation = (
            max(coherence_vals) - min(coherence_vals) < 0.1 if coherence_vals else False
        )

        return {
            "coherence_ceiling": coherence_ceiling,
            "coherence_mean": coherence_mean,
            "coherence_stagnation": coherence_stagnation,
            "coherence_trend": (
                "declining"
                if coherence_vals[-1] < coherence_vals[0]
                else (
                    "stable"
                    if abs(coherence_vals[-1] - coherence_vals[0]) < 0.1
                    else "improving"
                )
            ),
            "risk_assessment": (
                "High coherence stagnation risk"
                if coherence_stagnation
                else "Moderate coherence dynamics"
            ),
        }

    def _analyze_epistemic_quality(self) -> Dict:
        """Analyze compression and epistemic posture metrics."""
        if not self.epistemic_quality_history:
            return {}

        theory_metrics = [
            item.get("theory", {})
            for item in self.epistemic_quality_history
            if item.get("theory")
        ]
        reflection_metrics = [
            item.get("reflection", {})
            for item in self.epistemic_quality_history
            if item.get("reflection")
        ]

        return {
            "theory": self._mean_quality_metrics(theory_metrics),
            "reflection": self._mean_quality_metrics(reflection_metrics),
        }

    def _mean_quality_metrics(self, metric_rows: List[dict]) -> Dict:
        if not metric_rows:
            return {}

        metric_names = [
            "narrative_density",
            "uncertainty_presence",
            "contradiction_acknowledgment",
            "abstraction_sharpness",
            "causal_inflation",
            "semantic_repetition",
            "compression_score",
        ]
        return {
            name: round(
                mean(row.get(name, 0) for row in metric_rows),
                3,
            )
            for name in metric_names
        }

    def _analyze_transition_pressure(self) -> Dict:
        """Analyze transition pressure patterns with detailed calibration metrics."""
        if not self.transition_pressure_history:
            return {
                "status": "no_data",
                "message": "No transition pressure data recorded",
            }

        tp_data = self.transition_pressure_history

        # Basic metrics
        pressure_scores = [d["pressure_score"] for d in tp_data]
        stability_scores = [d["stability_score"] for d in tp_data]

        # TUNED METRICS: New breakpoints for calibration audit
        high_pressure_gt_0_5 = [d for d in tp_data if d["pressure_score"] > 0.5]
        high_pressure_gt_0_7 = [d for d in tp_data if d["pressure_score"] > 0.7]
        breakout_risk_count = sum(1 for d in tp_data if d["breakout_risk"])

        # Previous threshold (0.6) for backward compatibility
        high_pressure_days = [d for d in tp_data if d["pressure_score"] > 0.6]

        # Accuracy analysis when pressure > 0.5
        accuracy_when_pressure_gt_0_5 = 0.0
        if high_pressure_gt_0_5:
            correct = sum(
                1
                for d in high_pressure_gt_0_5
                if "prior_prediction_result" in d
                and d.get("prior_prediction_result", {}).get("direction_score", 0)
                >= 0.5
            )
            accuracy_when_pressure_gt_0_5 = correct / len(high_pressure_gt_0_5)

        # Accuracy when pressure > 0.7
        accuracy_when_pressure_gt_0_7 = 0.0
        if high_pressure_gt_0_7:
            correct = sum(
                1
                for d in high_pressure_gt_0_7
                if "prior_prediction_result" in d
                and d.get("prior_prediction_result", {}).get("direction_score", 0)
                >= 0.5
            )
            accuracy_when_pressure_gt_0_7 = correct / len(high_pressure_gt_0_7)

        # Accuracy analysis when pressure > 0.6 (legacy)
        accuracy_when_high_pressure = 0.0
        if high_pressure_days:
            correct_high_pressure = sum(
                1
                for d in high_pressure_days
                if "prior_prediction_result" in d
                and d.get("prior_prediction_result", {}).get("direction_score", 0)
                >= 0.5
            )
            accuracy_when_high_pressure = correct_high_pressure / len(
                high_pressure_days
            )

        # Accuracy when breakout_risk=True
        breakout_risk_days = [d for d in tp_data if d["breakout_risk"]]
        accuracy_when_breakout_risk = 0.0
        if breakout_risk_days:
            correct_breakout = sum(
                1
                for d in breakout_risk_days
                if "prior_prediction_result" in d
                and d.get("prior_prediction_result", {}).get("direction_score", 0)
                >= 0.5
            )
            accuracy_when_breakout_risk = correct_breakout / len(breakout_risk_days)

        # Transition capture rate: pressure > 0.5 AND directional move
        transition_attempts = sum(
            1 for d in tp_data if d["direction_bias"] in ["higher", "lower"]
        )
        transition_hits = sum(
            1
            for d in tp_data
            if d["direction_bias"] in ["higher", "lower"]
            and d.get("prediction_direction") in ["higher", "lower"]
        )
        transition_hit_rate = (
            transition_hits / transition_attempts if transition_attempts > 0 else 0.0
        )

        # TUNED: High-pressure transition capture (when pressure > 0.5 + directional bias)
        high_pressure_directional = sum(
            1
            for d in high_pressure_gt_0_5
            if d["direction_bias"] in ["higher", "lower"]
        )
        high_pressure_transitions_captured = sum(
            1
            for d in high_pressure_gt_0_5
            if d["direction_bias"] in ["higher", "lower"]
            and d.get("prediction_direction") in ["higher", "lower"]
        )
        transition_capture_under_high_pressure = (
            high_pressure_transitions_captured / high_pressure_directional
            if high_pressure_directional > 0
            else 0.0
        )

        # False positives: high pressure but direction missed
        false_positives = sum(
            1
            for d in high_pressure_gt_0_5
            if d.get("prediction_direction") == "uncertain"
        )

        # False negatives: low pressure but missed actual move (proxy: low stability + move happened)
        false_negatives = sum(
            1
            for d in tp_data
            if d["stability_score"] < 0.4
            and d.get("prediction_direction") in ["higher", "lower"]
        )

        # TUNED: Missed transitions analysis with pressure context
        missed_high_pressure = [
            d
            for d in tp_data
            if d["pressure_score"] > 0.5
            and d["direction_bias"] in ["higher", "lower"]
            and d.get("prediction_direction") == "uncertain"
        ]
        missed_high_pressure_avg_score = (
            mean([d["pressure_score"] for d in missed_high_pressure])
            if missed_high_pressure
            else 0.0
        )

        # Direction bias distribution
        direction_counts = {"higher": 0, "lower": 0, "neutral": 0}
        for d in tp_data:
            direction = d.get("direction_bias", "neutral")
            if direction in direction_counts:
                direction_counts[direction] += 1

        # Driver frequency
        driver_frequency = defaultdict(int)
        for d in tp_data:
            for driver in d.get("drivers", []):
                driver_frequency[driver] += 1

        return {
            "total_days": len(tp_data),
            "avg_pressure": float(mean(pressure_scores)) if pressure_scores else 0.0,
            "avg_stability": float(mean(stability_scores)) if stability_scores else 0.7,
            "pressure_distribution": {
                "gt_0_5": len(high_pressure_gt_0_5),
                "gt_0_6": len(high_pressure_days),
                "gt_0_7": len(high_pressure_gt_0_7),
            },
            "high_pressure_rate_0_5": (
                len(high_pressure_gt_0_5) / len(tp_data) if tp_data else 0.0
            ),
            "high_pressure_rate_0_7": (
                len(high_pressure_gt_0_7) / len(tp_data) if tp_data else 0.0
            ),
            "accuracy_when_pressure_gt_0_5": round(accuracy_when_pressure_gt_0_5, 3),
            "accuracy_when_pressure_gt_0_6": round(accuracy_when_high_pressure, 3),
            "accuracy_when_pressure_gt_0_7": round(accuracy_when_pressure_gt_0_7, 3),
            "breakout_risk_count": breakout_risk_count,
            "breakout_risk_rate": (
                breakout_risk_count / len(tp_data) if tp_data else 0.0
            ),
            "accuracy_when_breakout_risk": round(accuracy_when_breakout_risk, 3),
            "transition_hit_rate": round(transition_hit_rate, 3),
            "transition_capture_under_high_pressure": round(
                transition_capture_under_high_pressure, 3
            ),
            "false_positives": false_positives,
            "false_negatives": false_negatives,
            "missed_high_pressure_count": len(missed_high_pressure),
            "missed_high_pressure_avg_score": round(missed_high_pressure_avg_score, 3),
            "direction_bias_distribution": direction_counts,
            "top_drivers": sorted(
                driver_frequency.items(), key=lambda x: x[1], reverse=True
            )[:10],
        }

    def _analyze_predictions(self) -> Dict:
        """Analyze prediction probe performance."""
        if not self.prediction_history:
            return {}

        aligned_predictions = []
        for i in range(1, len(self.prediction_history)):
            current_day_record = self.prediction_history[i]
            previous_day_prediction_record = self.prediction_history[i - 1]

            if current_day_record.get(
                "prior_prediction_result"
            ) and previous_day_prediction_record.get("prediction"):
                aligned_predictions.append(
                    {
                        "date": current_day_record["date"],
                        "prediction": previous_day_prediction_record["prediction"],
                        "prior_prediction_result": current_day_record[
                            "prior_prediction_result"
                        ],
                        "contradiction_score": previous_day_prediction_record.get(
                            "contradiction_score", 0.0
                        ),
                        "regime_similarity": previous_day_prediction_record.get(
                            "regime_similarity", 0.0
                        ),
                        "theory_usefulness": previous_day_prediction_record.get(
                            "theory_usefulness"
                        ),
                        "theory_summary": previous_day_prediction_record.get(
                            "theory_summary", ""
                        ),
                        "transition_pressure_score": previous_day_prediction_record.get(
                            "transition_pressure_score", 0.0
                        ),
                        "transition_breakout_risk": previous_day_prediction_record.get(
                            "transition_breakout_risk", False
                        ),
                        "components_failed": previous_day_prediction_record.get(
                            "components_failed", []
                        ),
                        "reused_lessons": previous_day_prediction_record.get(
                            "reused_lessons", []
                        ),
                        "lessons_retired": previous_day_prediction_record.get(
                            "lessons_retired", 0
                        ),
                        "regime_matches": previous_day_prediction_record.get(
                            "regime_matches", []
                        ),
                    }
                )

        total = len(self.prediction_history)
        scored_count = len(aligned_predictions)

        def is_correct(row):
            return row["prior_prediction_result"].get("direction_score", 0) == 1.0

        def is_partial(row):
            return row["prior_prediction_result"].get("direction_score", 0) == 0.5

        correct = sum(1 for r in aligned_predictions if is_correct(r))
        partial = sum(1 for r in aligned_predictions if is_partial(r))
        mean_conf = (
            mean([r["prediction"].get("confidence", 0) for r in aligned_predictions])
            if aligned_predictions
            else 0.0
        )

        # Task 2.1: Median Confidence
        conf_list = [r["prediction"].get("confidence", 0) for r in aligned_predictions]
        median_conf = median(conf_list) if conf_list else 0.0

        # By direction
        directions = ["higher", "lower", "range_bound"]
        accuracy_by_direction = {}
        for d in directions:
            rows = [
                r
                for r in aligned_predictions
                if r.get("prediction", {}).get("direction") == d
            ]
            cnt = len(rows)
            acc = sum(1 for r in rows if is_correct(r)) / cnt if cnt else 0.0

            # Task 2.2: Extended direction metrics
            partial_acc = (
                (
                    sum(1 for r in rows if is_correct(r))
                    + sum(1 for r in rows if is_partial(r))
                )
                / cnt
                if cnt
                else 0.0
            )
            avg_conf_dir = (
                statistics.mean([r["prediction"].get("confidence", 0) for r in rows])
                if cnt
                else 0.0
            )
            accuracy_by_direction[d] = {
                "count": cnt,
                "accuracy": acc,
                "partial_accuracy": partial_acc,
                "avg_confidence": avg_conf_dir,
            }

        # Contradiction buckets
        def bucket(score: float) -> str:
            if score >= 0.66:
                return "high"
            if score >= 0.33:
                return "medium"
            return "low"

        buckets = {"low": [], "medium": [], "high": []}
        for r in aligned_predictions:
            b = bucket(r.get("contradiction_score", 0.0))
            buckets[b].append(r)

        accuracy_by_contradiction = {}
        for bname, rows in buckets.items():
            cnt = len(rows)
            acc = sum(1 for r in rows if is_correct(r)) / cnt if cnt else 0.0
            accuracy_by_contradiction[bname] = {"count": cnt, "accuracy": acc}

        # v1.5 Confidence Calibration Buckets (0.0-0.2, 0.2-0.4, 0.4-0.6, 0.6-0.8, 0.8-1.0)
        cal_buckets = {
            "0.0-0.2": [],
            "0.2-0.4": [],
            "0.4-0.6": [],
            "0.6-0.8": [],
            "0.8-1.0": [],
        }
        for r in aligned_predictions:
            c = r["prediction"].get("confidence", 0.0)
            if c < 0.2:
                cal_buckets["0.0-0.2"].append(r)
            elif c < 0.4:
                cal_buckets["0.2-0.4"].append(r)
            elif c < 0.6:
                cal_buckets["0.4-0.6"].append(r)
            elif c < 0.8:
                cal_buckets["0.6-0.8"].append(r)
            else:
                cal_buckets["0.8-1.0"].append(r)

        accuracy_by_confidence_bucket = {}
        gaps = []
        for bname, rows in cal_buckets.items():
            cnt = len(rows)
            acc = sum(1 for r in rows if is_correct(r)) / cnt if cnt else 0.0
            p_acc = (
                (
                    sum(1 for r in rows if is_correct(r))
                    + sum(1 for r in rows if is_partial(r))
                )
                / cnt
                if cnt
                else 0.0
            )
            avg_c = (
                statistics.mean([r["prediction"].get("confidence", 0) for r in rows])
                if cnt
                else 0.0
            )

            gap = avg_c - acc if cnt else 0.0
            if cnt > 0:
                gaps.append(abs(gap))

            accuracy_by_confidence_bucket[bname] = {
                "count": cnt,
                "actual_accuracy": acc,
                "partial_accuracy": p_acc,
                "avg_confidence": avg_c,
                "gap": gap,
            }

        calibration_score = statistics.mean(gaps) if gaps else 0.0

        # Usefulness Bands
        useful_buckets = {"0-0.3": [], "0.3-0.5": [], "0.5-0.7": [], "0.7+": []}
        for r in aligned_predictions:
            v = extract_usefulness_score(r.get("theory_usefulness", 0.0))
            if v < 0.3:
                useful_buckets["0-0.3"].append(r)
            elif v < 0.5:
                useful_buckets["0.3-0.5"].append(r)
            elif v < 0.7:
                useful_buckets["0.5-0.7"].append(r)
            else:
                useful_buckets["0.7+"].append(r)

        accuracy_by_usefulness = {
            b: {
                "count": len(rs),
                "accuracy": (
                    sum(1 for r in rs if is_correct(r)) / len(rs) if rs else 0.0
                ),
            }
            for b, rs in useful_buckets.items()
        }

        # Contradiction Bands
        contra_buckets = {"0-0.2": [], "0.2-0.5": [], "0.5+": []}
        for r in aligned_predictions:
            v = r.get("contradiction_score", 0.0)
            if v < 0.2:
                contra_buckets["0-0.2"].append(r)
            elif v < 0.5:
                contra_buckets["0.2-0.5"].append(r)
            else:
                contra_buckets["0.5+"].append(r)

        accuracy_by_contradiction_severity = {
            b: {
                "count": len(rs),
                "accuracy": (
                    sum(1 for r in rs if is_correct(r)) / len(rs) if rs else 0.0
                ),
            }
            for b, rs in contra_buckets.items()
        }

        # Theory Usefulness Analysis
        usefulness_scores = []
        missing_usefulness_count = 0
        for r in aligned_predictions:
            tu = r.get("theory_usefulness")
            # Ensure it's a dict and has 'score' and 'label'
            if tu and isinstance(tu, dict) and "score" in tu and "label" in tu:
                usefulness_scores.append(tu["score"])
            else:
                missing_usefulness_count += 1

        avg_theory_usefulness = mean(usefulness_scores) if usefulness_scores else 0.0
        high_usefulness_days = sum(1 for s in usefulness_scores if s > 0.7)

        # Accuracy when usefulness > 0.7
        high_usefulness_predictions = [
            r
            for r in aligned_predictions
            if (r.get("theory_usefulness") or {}).get("score", 0.0) > 0.7
        ]
        accuracy_when_high_usefulness = (
            sum(1 for r in high_usefulness_predictions if is_correct(r))
            / len(high_usefulness_predictions)
            if high_usefulness_predictions
            else 0.0
        )

        # Prediction Drift
        change_count = 0
        if len(self.prediction_history) > 1:
            for i in range(1, len(self.prediction_history)):
                if self.prediction_history[i - 1]["prediction"].get(
                    "direction"
                ) != self.prediction_history[i]["prediction"].get("direction"):
                    change_count += 1
        prediction_drift = (
            change_count / (len(self.prediction_history) - 1)
            if len(self.prediction_history) > 1
            else 0.0
        )

        # Rolling Confidence Drift
        conf_vals = [
            r["prediction"].get("confidence", 0) for r in self.prediction_history
        ]
        rolling_drift = {
            "7d": statistics.mean(conf_vals[-7:]) if len(conf_vals) >= 7 else 0.0,
            "15d": statistics.mean(conf_vals[-15:]) if len(conf_vals) >= 15 else 0.0,
        }

        # Task 2.2: Add 'uncertain'
        uncertain_rows = [
            r
            for r in aligned_predictions
            if r.get("prediction", {}).get("direction")
            == PredictionDirection.uncertain.value
        ]
        avg_conf_uncertain = (
            mean([r["prediction"].get("confidence", 0) for r in uncertain_rows])
            if uncertain_rows
            else 0.0
        )
        accuracy_by_direction["uncertain"] = {
            "count": len(uncertain_rows),
            "accuracy": 0.0,
            "partial_accuracy": 0.0,
            "avg_confidence": avg_conf_uncertain,
        }

        # Regime similarity > 0.9
        high_regime = [
            r for r in aligned_predictions if r.get("regime_similarity", 0.0) > 0.9
        ]
        regime_acc = (
            sum(1 for r in high_regime if is_correct(r)) / len(high_regime)
            if high_regime
            else 0.0
        )

        # Theory usefulness > 0.5
        useful = [
            r
            for r in aligned_predictions
            if extract_usefulness_score(r.get("theory_usefulness", 0.0)) > 0.5
        ]
        useful_acc = (
            sum(1 for r in useful if is_correct(r)) / len(useful) if useful else 0.0
        )

        # Task 2.4: Prediction slices by pressure
        pressure_gt_0_5 = [
            r
            for r in aligned_predictions
            if r.get("transition_pressure_score", 0.0) > 0.5
        ]
        acc_pressure_gt_0_5 = (
            sum(1 for r in pressure_gt_0_5 if is_correct(r)) / len(pressure_gt_0_5)
            if pressure_gt_0_5
            else 0.0
        )

        pressure_gt_0_7 = [
            r
            for r in aligned_predictions
            if r.get("transition_pressure_score", 0.0) > 0.7
        ]
        acc_pressure_gt_0_7 = (
            sum(1 for r in pressure_gt_0_7 if is_correct(r)) / len(pressure_gt_0_7)
            if pressure_gt_0_7
            else 0.0
        )

        # Task 2.5: False breakout
        false_breakouts = [
            r
            for r in aligned_predictions
            if r.get("transition_breakout_risk") and not is_correct(r)
        ]

        # Task 2.6: Best breakout capture
        best_breakout_captures = [
            r
            for r in aligned_predictions
            if r.get("transition_breakout_risk")
            and is_correct(r)
            and r["prediction"].get("direction")
            in [PredictionDirection.higher.value, PredictionDirection.lower.value]
        ]

        # Missed transition cases: range_bound -> higher / lower
        missed_range_to_higher = [
            r
            for r in aligned_predictions
            if r.get("prediction", {}).get("direction") == "range_bound"
            and r.get("prior_prediction_result", {}).get("actual_direction") == "higher"
            and not is_correct(r)
        ]
        missed_range_to_lower = [
            r
            for r in aligned_predictions
            if r.get("prediction", {}).get("direction") == "range_bound"
            and r.get("prior_prediction_result", {}).get("actual_direction") == "lower"
            and not is_correct(r)
        ]

        def sample_top(rows, n=5):
            return [
                {
                    "date": r.get("date"),
                    "theory_summary": r.get("theory_summary", ""),
                    "confidence": r.get("prediction", {}).get("confidence"),
                }
                for r in rows[:n]
            ]

        # Correlation Analysis
        correlation_coeff = 0.0
        confidences = [
            r["prediction"].get("confidence", 0)
            for r in aligned_predictions
            if r.get("prediction")
        ]
        scores = [
            r["prior_prediction_result"].get("direction_score", 0)
            for r in aligned_predictions
        ]
        if len(confidences) > 1 and len(scores) > 1:
            try:
                correlation_val = statistics.correlation(confidences, scores)
                correlation_coeff = correlation_val
            except Exception:
                correlation_coeff = 0.0

        # Item 2 Baselines Computation (Data-only baselines)
        actual_directions = [
            r.get("prior_prediction_result", {}).get("actual_direction")
            for r in aligned_predictions
            if r.get("prior_prediction_result", {}).get("actual_direction")
        ]

        if actual_directions:
            # 1. Always-range_bound baseline score
            rb_scores = []
            for act in actual_directions:
                if act == "range_bound":
                    rb_scores.append(1.0)
                elif act in {"higher", "lower"}:
                    rb_scores.append(0.5)
                else:
                    rb_scores.append(0.0)
            always_range_bound_baseline = mean(rb_scores)

            # 2. Majority class baseline score
            from collections import Counter
            counts = Counter(actual_directions)
            majority_class = counts.most_common(1)[0][0]
            maj_scores = []
            for act in actual_directions:
                if majority_class == "range_bound":
                    if act == "range_bound":
                        maj_scores.append(1.0)
                    elif act in {"higher", "lower"}:
                        maj_scores.append(0.5)
                    else:
                        maj_scores.append(0.0)
                elif majority_class == "uncertain":
                    if act == "uncertain":
                        maj_scores.append(0.5)
                    else:
                        maj_scores.append(0.0)
                else:
                    if act == majority_class:
                        maj_scores.append(1.0)
                    else:
                        maj_scores.append(0.0)
            majority_class_baseline = mean(maj_scores)

            system_mean_score = mean(scores) if scores else 0.0
            exceeds_baselines = (system_mean_score > majority_class_baseline) and (
                system_mean_score > always_range_bound_baseline
            )
        else:
            always_range_bound_baseline = 0.0
            majority_class_baseline = 0.0
            majority_class = "N/A"
            system_mean_score = 0.0
            exceeds_baselines = False

        return {
            "total_predictions": total,
            "scored_predictions": scored_count,
            "accuracy": correct / scored_count if scored_count else 0.0,
            "partial_accuracy": (
                (correct + partial) / scored_count if scored_count else 0.0
            ),
            "system_mean_direction_score": round(system_mean_score, 4),
            "majority_class_baseline_score": round(majority_class_baseline, 4),
            "always_range_bound_baseline_score": round(always_range_bound_baseline, 4),
            "majority_class": majority_class,
            "exceeds_baselines": exceeds_baselines,
            "uncertain_rate": (
                sum(
                    1
                    for r in self.prediction_history
                    if r.get("prediction", {}).get("direction") == "uncertain"
                )
                / total
                if total
                else 0.0
            ),
            "invalidation_rate": (
                sum(
                    1
                    for r in aligned_predictions
                    if r.get("prior_prediction_result", {}).get(
                        "invalidation_triggered"
                    )
                )
                / scored_count
                if scored_count
                else 0.0
            ),
            "mean_confidence": mean_conf,
            "median_confidence": median_conf,
            "confidence_accuracy_correlation": round(correlation_coeff, 3),
            "accuracy_by_direction": accuracy_by_direction,
            "accuracy_by_contradiction_bucket": accuracy_by_contradiction,
            "accuracy_by_confidence_bucket": accuracy_by_confidence_bucket,
            "calibration_score": round(calibration_score, 3),
            "prediction_drift": round(prediction_drift, 3),
            "rolling_drift": rolling_drift,
            "accuracy_when_pressure_gt_0_5": round(acc_pressure_gt_0_5, 3),
            "accuracy_when_pressure_gt_0_7": round(acc_pressure_gt_0_7, 3),
            "accuracy_regime_similarity_gt_0_9": regime_acc,
            "accuracy_theory_usefulness_gt_0_5": useful_acc,
            "accuracy_by_usefulness": accuracy_by_usefulness,
            "accuracy_by_contradiction_severity": accuracy_by_contradiction_severity,
            "missed_range_to_higher": {
                "count": len(missed_range_to_higher),
                "samples": sample_top(missed_range_to_higher),
            },
            "missed_range_to_lower": {
                "count": len(missed_range_to_lower),
                "samples": sample_top(missed_range_to_lower),
            },
            "false_breakouts": {
                "count": len(false_breakouts),
                "samples": sample_top(false_breakouts),
            },
            "best_breakout_captures": {
                "count": len(best_breakout_captures),
                "samples": sample_top(best_breakout_captures),
            },
            "avg_theory_usefulness": avg_theory_usefulness,
            "high_usefulness_days": high_usefulness_days,
            "accuracy_when_high_usefulness": accuracy_when_high_usefulness,
            "missing_usefulness_values": missing_usefulness_count,
        }

    def _detect_cognition_risks(self) -> List:
        """Detect potential cognition dysfunctions."""
        risks = []

        if not self.confidence_history or not self.contradiction_history:
            return risks

        # Overconfidence drift
        empirical_conf = [c["empirical"] for c in self.confidence_history]
        if len(empirical_conf) > 10:
            recent_mean = mean(empirical_conf[-10:])
            early_mean = mean(empirical_conf[:10])
            if recent_mean > early_mean + 0.2:
                risks.append(
                    {
                        "type": "overconfidence_drift",
                        "severity": "high",
                        "description": "Confidence increasing despite outcome validation",
                    }
                )

        # Contradiction suppression
        contradiction_scores = [c["score"] for c in self.contradiction_history]
        if len(contradiction_scores) > 10:
            if max(contradiction_scores[-10:]) < 0.3:
                risks.append(
                    {
                        "type": "contradiction_suppression",
                        "severity": "moderate",
                        "description": "Contradiction pressure artificially low",
                    }
                )

        # Theory rigidity
        if len(self.theory_themes) < 3:
            risks.append(
                {
                    "type": "theory_rigidity",
                    "severity": "high",
                    "description": "Very limited theory diversity; potential rigidity",
                }
            )

        # Coherence degradation
        coherence_vals = [c["coherence"] for c in self.confidence_history]
        if len(coherence_vals) > 20:
            if coherence_vals[-1] < coherence_vals[0] * 0.7:
                risks.append(
                    {
                        "type": "coherence_degradation",
                        "severity": "high",
                        "description": "Theoretical coherence declining significantly",
                    }
                )

        # Reflection stagnation
        if len(self.reflection_patterns) < 3:
            risks.append(
                {
                    "type": "reflection_stagnation",
                    "severity": "moderate",
                    "description": "Limited reflection diversity; potential shallow introspection",
                }
            )

        return risks

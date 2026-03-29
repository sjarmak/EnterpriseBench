"""
Verify Support Code Mapping task verifiers discriminate correctly.

For each of the 12 support-mapping tasks:
  (a) Ground truth answer → score >= 0.85
  (b) Empty answer → score <= 0.10
  (c) Partial answer → score between 0.3-0.7
  No false positives: wrong answer must not score > 0.5

Also verifies:
  - CSB-migrated tasks score >= 0.80 with ground truth answer
  - 4-checkpoint weighting (0.60/0.15/0.15/0.10) produces correct aggregation
"""

from __future__ import annotations

import json
import os
import subprocess
from pathlib import Path

import pytest


REPO_ROOT = Path(__file__).parent.parent
TASK_BASE = REPO_ROOT / "benchmarks" / "customer_escalation"

# All support-mapping task directories
SUPPORT_MAPPING_DIRS = sorted(TASK_BASE.glob("support-mapping-*"))

# Verifier scripts in checkpoint order
VERIFIERS = [
    "checks/check_code_paths.sh",
    "checks/check_ownership.sh",
    "checks/check_severity.sh",
    "checks/check_related_issues.sh",
]

# Checkpoint weights from task definitions (must sum to 1.0)
WEIGHTS = [0.60, 0.15, 0.15, 0.10]


def _run_verifier(
    task_dir: Path,
    verifier: str,
    workspace: Path,
) -> dict:
    """Run a single verifier script and return parsed JSON output."""
    verifier_path = task_dir / verifier
    assert verifier_path.exists(), f"Verifier not found: {verifier_path}"

    env = os.environ.copy()
    env["WORKSPACE"] = str(workspace)
    env["TASK_DIR"] = str(task_dir)
    env["TASK_ID"] = "test"

    result = subprocess.run(
        ["bash", str(verifier_path)],
        capture_output=True,
        text=True,
        timeout=30,
        cwd=str(workspace),
        env=env,
    )

    stdout = result.stdout.strip()
    try:
        return json.loads(stdout)
    except (json.JSONDecodeError, ValueError):
        return {
            "score": 1.0 if result.returncode == 0 else 0.0,
            "passed": result.returncode == 0,
            "detail": stdout or result.stderr.strip(),
        }


def _create_answer(workspace: Path, answer_data: dict) -> None:
    """Write answer.json to the workspace agent_output directory."""
    output_dir = workspace / "agent_output"
    output_dir.mkdir(parents=True, exist_ok=True)
    (output_dir / "answer.json").write_text(json.dumps(answer_data, indent=2))


def _load_ground_truth(task_dir: Path) -> dict:
    """Load ground_truth.json from a task directory."""
    gt_path = task_dir / "ground_truth.json"
    assert gt_path.exists(), f"No ground_truth.json in {task_dir}"
    return json.loads(gt_path.read_text())


def _build_ground_truth_answer(gt: dict) -> dict:
    """Build a 'perfect' answer from ground truth data."""
    gt_data = gt.get("ground_truth", gt)
    required = gt_data.get("required_files", [])
    sufficient = gt_data.get("sufficient_files", [])
    ownership_kw = gt.get("ownership_keywords", [])
    expected_severity = gt.get("expected_severity", "high")
    related_refs = gt.get("related_references", [])

    return {
        "code_paths": [
            {"path": f["path"], "repo": f["repo"]}
            for f in required + sufficient
        ],
        "ownership": {
            "subsystem": " ".join(ownership_kw),
            "description": " ".join(kw.replace("-", " ") for kw in ownership_kw),
        },
        "severity": {
            "level": expected_severity,
            "rationale": f"Production impact assessed as {expected_severity}",
        },
        "related_issues": [
            {"reference": ref, "type": "doc"} for ref in related_refs
        ] + [
            {"reference": sf["path"], "type": "code"}
            for sf in sufficient
        ],
    }


def _build_partial_answer(gt: dict) -> dict:
    """Build a partial answer — first required file, partial ownership, adjacent severity."""
    gt_data = gt.get("ground_truth", gt)
    required = gt_data.get("required_files", [])
    ownership_kw = gt.get("ownership_keywords", [])
    expected_severity = gt.get("expected_severity", "high")
    related_refs = gt.get("related_references", [])

    # Include only first required file (not all)
    partial_files = required[:1] if required else []

    # Include only 1 ownership keyword
    partial_ownership = ownership_kw[:1] if ownership_kw else []

    # Adjacent severity level (off by one)
    severity_adjacent = {
        "critical": "high",
        "high": "medium",
        "medium": "low",
        "low": "medium",
    }
    adj_severity = severity_adjacent.get(expected_severity, "medium")

    # Include only first related reference
    partial_refs = related_refs[:1] if related_refs else []

    return {
        "code_paths": [
            {"path": f["path"], "repo": f["repo"]} for f in partial_files
        ],
        "ownership": {
            "subsystem": " ".join(partial_ownership),
        },
        "severity": {
            "level": adj_severity,
            "rationale": "Some production impact observed",
        },
        "related_issues": [
            {"reference": ref, "type": "doc"} for ref in partial_refs
        ],
    }


def _build_empty_answer() -> dict:
    """Build an empty answer."""
    return {
        "code_paths": [],
        "ownership": {},
        "severity": {},
        "related_issues": [],
    }


def _build_wrong_answer() -> dict:
    """Build a wrong answer with plausible but incorrect data."""
    return {
        "code_paths": [
            {"path": "pkg/wrong/totally_unrelated.go", "repo": "kubernetes"},
            {"path": "internal/fake/module.go", "repo": "terraform"},
        ],
        "ownership": {
            "subsystem": "authentication middleware",
            "description": "OAuth token refresh handler",
        },
        "severity": {
            "level": "low",
            "rationale": "Minor cosmetic issue in dev environment",
        },
        "related_issues": [
            {"reference": "docs/contributing.md", "type": "doc"},
            {"reference": "CHANGELOG.md", "type": "doc"},
        ],
    }


def _weighted_score(results: list[dict], weights: list[float]) -> float:
    """Compute weighted score from verifier results."""
    total = sum(
        r.get("score", 0.0) * w
        for r, w in zip(results, weights)
    )
    weight_sum = sum(weights)
    return total / weight_sum if weight_sum > 0 else 0.0


@pytest.fixture(params=[d.name for d in SUPPORT_MAPPING_DIRS], ids=lambda x: x)
def task_env(request, tmp_path: Path) -> tuple[str, Path, Path, dict]:
    """Parametrized fixture for each support-mapping task."""
    task_name = request.param
    task_dir = TASK_BASE / task_name

    # Load ground truth
    gt = _load_ground_truth(task_dir)

    # Create workspace
    workspace = tmp_path / "workspace"
    workspace.mkdir()

    return task_name, task_dir, workspace, gt


def _run_all_verifiers(
    task_dir: Path, workspace: Path
) -> list[dict]:
    """Run all 4 verifiers and return results."""
    return [_run_verifier(task_dir, v, workspace) for v in VERIFIERS]


class TestGroundTruthAnswer:
    """(a) Ground truth answer should score >= 0.85"""

    def test_ground_truth_scores_high(
        self, task_env: tuple[str, Path, Path, dict]
    ) -> None:
        task_name, task_dir, workspace, gt = task_env

        answer = _build_ground_truth_answer(gt)
        _create_answer(workspace, answer)

        results = _run_all_verifiers(task_dir, workspace)
        total = _weighted_score(results, WEIGHTS)
        assert total >= 0.85, (
            f"{task_name}: ground truth answer scored {total:.2f} < 0.85. "
            f"Per-checkpoint: {[r.get('score', 0) for r in results]}"
        )


class TestEmptyAnswer:
    """(b) Empty answer should score <= 0.10"""

    def test_empty_answer_scores_low(
        self, task_env: tuple[str, Path, Path, dict]
    ) -> None:
        task_name, task_dir, workspace, gt = task_env

        answer = _build_empty_answer()
        _create_answer(workspace, answer)

        results = _run_all_verifiers(task_dir, workspace)
        total = _weighted_score(results, WEIGHTS)
        assert total <= 0.10, (
            f"{task_name}: empty answer scored {total:.2f} > 0.10. "
            f"Per-checkpoint: {[r.get('score', 0) for r in results]}"
        )


class TestPartialAnswer:
    """(c) Partial answer should score between 0.3-0.7"""

    def test_partial_answer_scores_mid(
        self, task_env: tuple[str, Path, Path, dict]
    ) -> None:
        task_name, task_dir, workspace, gt = task_env

        answer = _build_partial_answer(gt)
        _create_answer(workspace, answer)

        results = _run_all_verifiers(task_dir, workspace)
        total = _weighted_score(results, WEIGHTS)
        assert 0.20 <= total <= 0.80, (
            f"{task_name}: partial answer scored {total:.2f}, "
            f"expected 0.20-0.80. "
            f"Per-checkpoint: {[r.get('score', 0) for r in results]}"
        )


class TestWrongAnswer:
    """Wrong answer must not score > 0.5 (no false positives)"""

    def test_wrong_answer_scores_low(
        self, task_env: tuple[str, Path, Path, dict]
    ) -> None:
        task_name, task_dir, workspace, gt = task_env

        answer = _build_wrong_answer()
        _create_answer(workspace, answer)

        results = _run_all_verifiers(task_dir, workspace)
        total = _weighted_score(results, WEIGHTS)
        assert total <= 0.5, (
            f"{task_name}: wrong answer scored {total:.2f} > 0.5 — "
            f"false positive! Per-checkpoint: {[r.get('score', 0) for r in results]}"
        )


class TestNoAnswerFile:
    """Missing answer file should score 0"""

    def test_no_answer_file(
        self, task_env: tuple[str, Path, Path, dict]
    ) -> None:
        task_name, task_dir, workspace, _ = task_env

        # Don't create answer.json at all
        results = _run_all_verifiers(task_dir, workspace)
        total = _weighted_score(results, WEIGHTS)
        assert total <= 0.10, (
            f"{task_name}: missing answer scored {total:.2f} > 0.10"
        )


class TestCSBLineage:
    """CSB-migrated tasks should score >= 0.80 with ground truth answer"""

    def test_csb_tasks_score_high(
        self, task_env: tuple[str, Path, Path, dict]
    ) -> None:
        task_name, task_dir, workspace, gt = task_env

        # All 12 have csb_lineage
        assert "csb_lineage" in gt, f"{task_name}: missing csb_lineage"

        answer = _build_ground_truth_answer(gt)
        _create_answer(workspace, answer)

        results = _run_all_verifiers(task_dir, workspace)
        total = _weighted_score(results, WEIGHTS)
        assert total >= 0.80, (
            f"{task_name} (CSB-migrated): scored {total:.2f} < 0.80. "
            f"Per-checkpoint: {[r.get('score', 0) for r in results]}"
        )


class TestCheckpointWeighting:
    """Verify 4-checkpoint weighting (0.60/0.15/0.15/0.10) produces correct aggregation"""

    def test_weights_sum_to_one(self) -> None:
        assert abs(sum(WEIGHTS) - 1.0) < 1e-9, (
            f"Weights sum to {sum(WEIGHTS)}, expected 1.0"
        )

    def test_task_toml_weights_match(self) -> None:
        """Verify all 12 task.toml files use the expected checkpoint weights."""
        try:
            import tomllib
        except ImportError:
            import tomli as tomllib  # type: ignore[no-redef]

        for task_dir in SUPPORT_MAPPING_DIRS:
            toml_path = task_dir / "task.toml"
            assert toml_path.exists(), f"No task.toml in {task_dir}"
            with open(toml_path, "rb") as f:
                task = tomllib.load(f)
            checkpoints = task.get("checkpoints", [])
            assert len(checkpoints) == 4, (
                f"{task_dir.name}: expected 4 checkpoints, got {len(checkpoints)}"
            )
            actual_weights = [cp["weight"] for cp in checkpoints]
            assert actual_weights == WEIGHTS, (
                f"{task_dir.name}: weights {actual_weights} != expected {WEIGHTS}"
            )

    def test_weighted_aggregation_math(self) -> None:
        """Verify the weighted score computation matches expected math."""
        from eb_verify.scoring import CheckpointResult, compute_score

        # Simulate: code_paths=1.0, ownership=0.5, severity=0.5, related=0.0
        results = [
            CheckpointResult(name="code_paths", weight=0.60, passed=True, score=1.0),
            CheckpointResult(name="ownership", weight=0.15, passed=True, score=0.5),
            CheckpointResult(name="severity", weight=0.15, passed=True, score=0.5),
            CheckpointResult(name="related_issues", weight=0.10, passed=False, score=0.0),
        ]
        expected = (1.0 * 0.60 + 0.5 * 0.15 + 0.5 * 0.15 + 0.0 * 0.10) / 1.0
        actual = compute_score(results)
        assert abs(actual - expected) < 1e-6, (
            f"compute_score returned {actual}, expected {expected}"
        )

    def test_code_paths_dominates(self) -> None:
        """code_paths (weight=0.60) should dominate the total score."""
        # code_paths=1.0, all others=0.0 should give 0.60
        results_high_code = [
            {"score": 1.0}, {"score": 0.0}, {"score": 0.0}, {"score": 0.0}
        ]
        # code_paths=0.0, all others=1.0 should give 0.40
        results_low_code = [
            {"score": 0.0}, {"score": 1.0}, {"score": 1.0}, {"score": 1.0}
        ]
        score_high = _weighted_score(results_high_code, WEIGHTS)
        score_low = _weighted_score(results_low_code, WEIGHTS)
        assert score_high > score_low, (
            f"code_paths=1.0 ({score_high:.2f}) should beat code_paths=0.0 ({score_low:.2f})"
        )
        assert abs(score_high - 0.60) < 1e-6
        assert abs(score_low - 0.40) < 1e-6

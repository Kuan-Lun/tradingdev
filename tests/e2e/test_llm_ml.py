"""Explicit model-driven ML research with independently checked MCP artifacts."""

from __future__ import annotations

import asyncio
import hashlib
import json
import pickle
import re
from dataclasses import asdict, dataclass, replace
from pathlib import Path
from typing import TYPE_CHECKING, Any

import numpy as np
import pandas as pd
import pytest

from tests.app.test_run_metrics import _publish, _scope
from tests.data_cache import seed_market_cache
from tests.e2e.codex_harness import run_codex
from tests.e2e.conversation import visible_text
from tests.e2e.llm_client import ToolCall, codex_calls, run_local_model
from tests.e2e.ml_report_evidence import (
    ML_REPORT_REQUEST,
    _reject_unsupported_sample_claims,
    _require_unknown_sample_provenance,
    seed_ml_report_candidates,
    verify_ml_report_outcome,
)
from tests.e2e.workflow_arguments import effective_workflow_calls
from tests.integration.mcp_harness import temporary_mcp_workspace
from tradingdev.adapters.storage.filesystem import WorkspacePaths
from tradingdev.adapters.storage.ml_datasets import MLDatasetStore
from tradingdev.adapters.storage.sqlite import SQLiteStore
from tradingdev.app.ml_service import MLService
from tradingdev.app.run_service import RunService
from tradingdev.domain.ml.leaderboard import ProducerSource, signal_fingerprint
from tradingdev.domain.ml.registry.artifact_store import ModelArtifactStore
from tradingdev.domain.ml.registry.leaderboard_store import LeaderboardStore

if TYPE_CHECKING:
    from tests.e2e.conversation import ModelTurn
    from tests.integration.mcp_harness import MCPWorkspace
    from tradingdev.domain.ml.leaderboard import LeaderboardEntry

ML_TOOLS = [
    "get_ml_contract",
    "build_dataset",
    "train_model",
    "predict",
    "evaluate_signal",
    "leaderboard",
]
DATASET_ARGUMENTS = {
    "symbol": "BTC/USDT",
    "timeframe": "1h",
    "start_date": "2024-01-01",
    "end_date": "2024-01-10",
    "feature_set": "returns",
    "horizon": 1,
    "source": "binance_vision",
    "market_type": "spot",
}
MODEL_PARAMETERS = {"n_estimators": 12, "max_depth": 3, "n_jobs": 1, "random_state": 42}
TRAINING_ARGUMENTS = {
    "model_kind": "lightgbm_direction",
    "parameters": MODEL_PARAMETERS,
    "validation": "purged_walk_forward",
    "n_folds": 3,
    "embargo": 1,
    "min_train_bars": 20,
}
PREDICTION_ARGUMENTS = {"offset": 0, "limit": 20}
IN_SAMPLE_STATEMENT = "本次 predict／evaluate_signal 使用訓練集，屬 in-sample。"
VALIDATION_STATEMENT = (
    "validation 衡量訓練流程的樣本外表現，不是此 artifact 的樣本外預測。"
)
ML_PROMPT = f"""請透過 TradingDev MCP 完成一個小型 ML 研究流程。
先 get_ml_contract，確認以下 feature set、model kind、validation、leaderboard metric
皆由契約提供。再 build_dataset，參數為 {json.dumps(DATASET_ARGUMENTS)}。
行情已預先放入後端快取；不要下載行情或寫入策略，也不必啟動回測確認單。
接著 train_model，dataset_id 使用剛回傳的 ID，其餘參數為
{json.dumps(TRAINING_ARGUMENTS)}。檢查 validation 成功及 leakage_audit_clean=true。
之後 predict，以剛回傳 model_id 與同一 dataset_id 取得預覽，
使用 offset=0、limit=20。檢查 n_rows 是完整資料集筆數，next_offset 可續讀。
再 evaluate_signal，使用同一 model_id、dataset_id，設 window=12、n_quantiles=2、
record=true，讓後端評估全部資料列；不需把預覽陣列傳入或讀完每一頁。
若工具回報錯誤，讀取原因再修正。
最後 leaderboard(metric="hit_rate", dataset_id=同一資料集ID)，
確認排名中包含這次 recorded.entry_id，
與相同 model_id、dataset_id。讀取 caveats，不要把最高排名當作獲利保證。
完成後回覆 dataset_id、model_id、entry_id，並逐字附上以下兩句以區分證據：
{IN_SAMPLE_STATEMENT}
{VALIDATION_STATEMENT}
只使用 MCP 工具，不使用 shell 或直接讀寫檔案；不要請求已授權研究的額外確認。
"""


def ml_market_frame() -> pd.DataFrame:
    """A small reproducible market with both directions and varying returns."""
    rng = np.random.default_rng(42)
    steps = np.arange(240)
    returns = 0.003 * np.sin(steps / 7) + rng.normal(0, 0.0008, len(steps))
    close = 100 * np.cumprod(1 + returns)
    return pd.DataFrame(
        {
            "timestamp": pd.date_range("2024-01-01", periods=240, freq="h", tz="UTC"),
            "open": close * 0.999,
            "high": close * 1.003,
            "low": close * 0.997,
            "close": close,
            "volume": 100 + rng.uniform(0, 50, len(steps)),
        }
    )


@dataclass(frozen=True)
class MLEvidence:
    dataset: dict[str, Any]
    model: dict[str, Any]
    prediction: dict[str, Any]
    evaluation: dict[str, Any]
    leaderboard: dict[str, Any]


def assert_ml_workflow(calls: list[ToolCall]) -> MLEvidence:
    """Require linked identities, bounded previews and complete backend evaluation."""
    calls = effective_workflow_calls(calls)
    assert all(call.name in ML_TOOLS for call in calls), "Unexpected non-ML tool"
    previous = -1
    ordered: list[ToolCall] = []
    for name in ML_TOOLS:
        index = next(
            (
                index
                for index, call in enumerate(calls)
                if index > previous
                and call.name == name
                and isinstance(call.result, dict)
                and call.result.get("success") is True
            ),
            None,
        )
        assert index is not None, f"Missing successful ordered ML step: {name}"
        ordered.append(calls[index])
        previous = index
    contract, built, trained, predicted, evaluated, ranked = ordered
    for key, expected in (
        ("feature_sets", "returns"),
        ("model_kinds", "lightgbm_direction"),
        ("validation_schemes", "purged_walk_forward"),
    ):
        assert expected in {entry["name"] for entry in contract.result[key]}
    assert "hit_rate" in contract.result["leaderboard_metrics"]
    for key, value in DATASET_ARGUMENTS.items():
        assert built.arguments.get(key) == value, f"Dataset request mismatch: {key}"
        assert built.result["dataset"][key] == value, f"Dataset result mismatch: {key}"
    dataset = built.result["dataset"]
    dataset_id = dataset["dataset_id"]
    assert 100 < dataset["rows"] < 250, "Expected the complete small dataset"
    for key, value in TRAINING_ARGUMENTS.items():
        assert trained.arguments.get(key) == value, f"Training request mismatch: {key}"
    assert trained.arguments.get("dataset_id") == dataset_id
    model = trained.result["model"]
    assert model["dataset_id"] == dataset_id
    assert model["n_train_samples"] == dataset["rows"]
    for key, value in MODEL_PARAMETERS.items():
        assert model["parameters"][key] == value
    validation = model["validation"]
    assert validation["scheme"] == "purged_walk_forward"
    assert validation["artifact_trained_on"] == "all_bars"
    assert validation["leakage_audit_clean"] is True
    assert validation["label_horizon"] == 1 and validation["embargo"] == 1
    assert validation["n_folds"] == len(validation["folds"]) == 3
    assert validation["purged_bars"] >= 3 and validation["embargoed_bars"] >= 3
    assert all(fold["train_bars"] >= 20 for fold in validation["folds"])
    identity = {"model_id": model["model_id"], "dataset_id": dataset_id}
    assert predicted.arguments == {**identity, **PREDICTION_ARGUMENTS}, (
        "Prediction identity or preview bounds mismatch"
    )
    prediction = predicted.result["prediction"]
    for key, value in identity.items():
        assert prediction[key] == value, "Prediction result identity mismatch"
        assert evaluated.arguments.get(key) == value, "Evaluation identity mismatch"
    assert prediction["n_rows"] == dataset["rows"]
    assert prediction["horizon"] == 1
    assert prediction["offset"] == 0
    assert prediction["limit"] == prediction["next_offset"] == 20
    for key in ("signal", "forward_returns"):
        assert len(prediction[key]) == 20, "Prediction preview must be bounded"
    assert not {"signal", "forward_returns", "horizon"} & evaluated.arguments.keys(), (
        "Evaluation must use saved identities, not caller arrays or horizon"
    )
    for key, value in {"record": True, "window": 12, "n_quantiles": 2}.items():
        assert evaluated.arguments.get(key) == value
    evaluation = evaluated.result
    for key, value in identity.items():
        assert evaluation[key] == value, "Evaluation result identity mismatch"
    assert evaluation["horizon"] == 1 and evaluation["window"] == 12
    assert evaluation["n_observations"] == dataset["rows"]
    assert evaluation["recorded"]["n_candidates"] == 1
    assert evaluation.get("producer_source") == "backend_model"
    assert evaluation["recorded"].get("producer_source") == "backend_model"
    assert evaluation["recorded"]["training_dataset_id"] == dataset_id
    assert ranked.arguments.get("metric") == "hit_rate"
    assert ranked.arguments.get("dataset_id") == dataset_id
    leaderboard = ranked.result
    # The echo is source-qualified: one tool ranks two sources now, so the
    # answer names the one it read instead of restating a bare metric name.
    assert leaderboard["metric"] == "signal.hit_rate"
    assert leaderboard["source"] == "signal"
    assert leaderboard["n_candidates"] == leaderboard["n_ranked"] == 1
    assert leaderboard["caveats"], "Leaderboard must retain interpretation caveats"
    row = leaderboard["ranked"][0]
    assert row["entry_id"] == evaluation["recorded"]["entry_id"]
    assert row["dataset_id"] == dataset_id and row["model_id"] == model["model_id"]
    assert row["training_dataset_id"] == dataset_id
    assert row.get("producer_source") == "backend_model"
    assert row["n_observations"] == dataset["rows"]
    assert row["value"] == evaluation["metrics"]["hit_rate"]
    assert row["parameters"] == model["parameters"]
    assert row["signal_fingerprint"] == prediction["signal_fingerprint"]
    assert row["signal_fingerprint"] == evaluation["signal_fingerprint"]
    assert row["signal_fingerprint"] == evaluation["recorded"]["signal_fingerprint"]
    return MLEvidence(dataset, model, prediction, evaluation, leaderboard)


def assert_ml_artifacts(workspace: MCPWorkspace, evidence: MLEvidence) -> None:
    """Read actual artifacts and recompute labels and hit rate from seeded prices."""
    paths = WorkspacePaths(workspace.workspace)
    dataset = evidence.dataset
    frame, manifest = MLDatasetStore(paths.ml_datasets).load(dataset["dataset_id"])
    assert manifest["content_hash"] == dataset["content_hash"]
    assert manifest["source"] == "binance_vision"
    assert manifest["market_type"] == "spot"
    parquet = Path(dataset["path"])
    assert parquet.is_relative_to(paths.ml_datasets)
    assert hashlib.sha256(parquet.read_bytes()).hexdigest() == dataset["content_hash"]
    seed = ml_market_frame().set_index("timestamp")
    expected = (seed["close"].shift(-1) / seed["close"] - 1).loc[frame["timestamp"]]
    np.testing.assert_allclose(frame["forward_return"], expected, rtol=0, atol=1e-14)
    np.testing.assert_array_equal(frame["target"], np.sign(expected))
    np.testing.assert_array_equal(
        evidence.prediction["forward_returns"], expected.iloc[:20]
    )

    models = ModelArtifactStore(paths.models)
    artifact = models.load(evidence.model["model_id"])
    assert artifact.training_dataset_id == dataset["dataset_id"]
    assert artifact.n_train_samples == len(frame)
    assert list(artifact.feature_names) == dataset["feature_columns"]
    assert artifact.parameters == evidence.model["parameters"]
    fitted = pickle.loads(models.path_for(evidence.model["model_id"]).read_bytes())
    signal = fitted.predict(frame).to_numpy()
    np.testing.assert_array_equal(signal[:20], evidence.prediction["signal"])
    realized = expected.to_numpy()
    scored = (signal != 0) & (realized != 0)
    hit_rate = float((np.sign(signal[scored]) == np.sign(realized[scored])).mean())
    assert evidence.evaluation["metrics"]["hit_rate"] == pytest.approx(hit_rate)
    entries = LeaderboardStore(paths.ml_leaderboard).entries()
    assert len(entries) == 1
    entry = entries[0]
    assert entry.entry_id == evidence.evaluation["recorded"]["entry_id"]
    assert entry.dataset_id == dataset["dataset_id"]
    assert entry.model_id == evidence.model["model_id"]
    assert entry.n_observations == len(frame)
    assert entry.metric("hit_rate") == pytest.approx(hit_rate)
    assert entry.context.data_fingerprint == dataset["content_hash"]
    assert entry.parameters == artifact.parameters
    assert entry.training_dataset_id == artifact.training_dataset_id
    assert entry.producer_source is ProducerSource.BACKEND_MODEL
    assert entry.signal_fingerprint == signal_fingerprint(signal.tolist())
    assert entry.signal_fingerprint == evidence.prediction["signal_fingerprint"]
    assert not list(paths.runs.glob("*/manifest.json")), "ML research must not backtest"


def seed_ml_markets(workspace: MCPWorkspace) -> None:
    """Provide selected spot prices alongside a different default futures market."""
    seed_market_cache(
        workspace.data_root / "processed", ml_market_frame(), market_type="spot"
    )
    other_market = ml_market_frame()
    other_market["close"] *= 2
    workspace.seed_market(other_market)


@dataclass(frozen=True)
class TrainingProvenanceCase:
    model_id: str
    training_dataset_id: str
    overlapping_dataset_id: str
    historical: tuple[LeaderboardEntry, ...]

    @property
    def request(self) -> str:
        ids = "、".join(entry.entry_id for entry in self.historical)
        return (
            f"請用已保存的模型 {self.model_id}，分別對資料集 "
            f"{self.training_dataset_id}、{self.overlapping_dataset_id} "
            "做訊號評估並保存結果。再查詢既有候選 "
            f"{ids}，一起判斷這 {len(self.historical) + 2} 筆結果能否支持"
            "未見資料上的表現，說明理由。"
            "請以表格每個候選一列，列出完整候選識別碼、訓練及評估資料來源，"
            "訊號如何產生，以及你對證據的判讀。這次只評估既有模型及解讀研究，"
            "不要重新取得行情、訓練模型、執行回測或改寫既有候選。"
        )


async def prepare_training_provenance(
    workspace: MCPWorkspace,
) -> TrainingProvenanceCase:
    """Create real model inputs and an external series using the same model label."""
    seed_ml_markets(workspace)
    async with workspace.connect() as client:
        built = await client.call("build_dataset", **DATASET_ARGUMENTS)
        overlapping = await client.call(
            "build_dataset", **{**DATASET_ARGUMENTS, "end_date": "2024-01-09"}
        )
        assert built["success"] and overlapping["success"]
        dataset_id = built["dataset"]["dataset_id"]
        other_id = overlapping["dataset"]["dataset_id"]
        assert dataset_id != other_id
        trained = await client.call(
            "train_model", dataset_id=dataset_id, **TRAINING_ARGUMENTS
        )
        assert trained["success"], trained
    paths = WorkspacePaths(workspace.workspace)
    datasets = MLDatasetStore(paths.ml_datasets)
    train_frame, _ = datasets.load(dataset_id)
    other_frame, _ = datasets.load(other_id)
    assert set(other_frame["timestamp"]) < set(train_frame["timestamp"])
    historical = seed_ml_report_candidates(paths)
    undeclared = replace(
        historical[0],
        entry_id="purple-signal-3",
        label="紫杉訊號研究",
        method_family="other",
        method_name="",
        parameters={},
    )
    assert not LeaderboardStore(paths.ml_leaderboard).record(undeclared)
    external = MLService(workspace=paths).evaluate_signal(
        np.linspace(-1.0, 1.0, len(train_frame)).tolist(),
        train_frame["forward_return"].astype(float).tolist(),
        model_id=trained["model"]["model_id"],
        dataset_id=dataset_id,
        record=True,
    )
    caller = next(
        entry
        for entry in LeaderboardStore(paths.ml_leaderboard).entries()
        if entry.entry_id == external["recorded"]["entry_id"]
    )
    assert caller.producer_source is ProducerSource.CALLER_ARRAY
    assert caller.training_dataset_id == dataset_id
    return TrainingProvenanceCase(
        trained["model"]["model_id"],
        dataset_id,
        other_id,
        (*historical, undeclared, caller),
    )


def assert_training_provenance(
    workspace: MCPWorkspace,
    case: TrainingProvenanceCase,
    attempted: list[ToolCall],
    final_text: str,
    readonly_tools: set[str],
) -> None:
    """Check real evidence and visible explanation coverage; review prose separately."""
    permitted = readonly_tools | {
        "evaluate_signal",
        "save_research_note",
        "export_research_note",
        "generate_report",
    }
    assert all(call.name in permitted for call in attempted), "Unrequested mutation"
    calls = effective_workflow_calls(attempted)
    dataset_ids = {case.training_dataset_id, case.overlapping_dataset_id}
    for call in calls:
        if call.name == "evaluate_signal":
            assert call.arguments.get("model_id") == case.model_id
            assert call.arguments.get("dataset_id") in dataset_ids
            assert call.arguments.get("record") is True
    successful = [
        call
        for call in calls
        if isinstance(call.result, dict) and call.result.get("success") is True
    ]
    report_paths = {
        call.result["path"] for call in successful if call.name == "generate_report"
    }
    if len(report_paths) > 1:
        # Catch the observed cross-report claim; other wording still needs review.
        assert "所有內容保存在同一份" not in visible_text(final_text), (
            "Multiple report files must not be described as one file"
        )
    assert any(call.name == "get_ml_contract" for call in successful)
    evaluations = {
        call.arguments["dataset_id"]: call.result
        for call in successful
        if call.name == "evaluate_signal"
    }
    assert evaluations.keys() == dataset_ids, "Both requested evaluations are required"
    discovered = {
        row["entry_id"]
        for call in successful
        if call.name == "leaderboard"
        for group in ("ranked", "skipped")
        for row in call.result[group]
    }
    assert {entry.entry_id for entry in case.historical} <= discovered
    paths = WorkspacePaths(workspace.workspace)
    stored = {
        entry.entry_id: entry
        for entry in LeaderboardStore(paths.ml_leaderboard).entries()
    }
    for entry in case.historical:
        assert stored[entry.entry_id] == entry, "Historical evidence was changed"
    expected_ids: list[str] = []
    for dataset_id, result in evaluations.items():
        recorded = result["recorded"]
        entry = stored[recorded["entry_id"]]
        assert result.get("producer_source") == "backend_model"
        assert recorded.get("producer_source") == "backend_model"
        assert entry.producer_source is ProducerSource.BACKEND_MODEL
        assert recorded["training_dataset_id"] == case.training_dataset_id
        assert entry.training_dataset_id == case.training_dataset_id
        assert entry.model_id == case.model_id and entry.dataset_id == dataset_id
        expected_ids.append(entry.entry_id)
    expected_ids.extend(entry.entry_id for entry in case.historical)
    assert len(stored) == len(expected_ids), "Cross-source candidates must coexist"
    for call in successful:
        if call.name == "leaderboard":
            for row in [*call.result["ranked"], *call.result["skipped"]]:
                if row["entry_id"] in expected_ids:
                    assert (
                        row.get("producer_source")
                        == stored[row["entry_id"]].producer_source
                    ), "Leaderboard changed the saved producer source"
    rows: dict[str, str] = {}
    for entry_id in expected_ids:
        matches = [
            line
            for line in final_text.splitlines()
            if line.lstrip().startswith("|") and entry_id in line
        ]
        assert len(matches) == 1, f"Missing candidate explanation row: {entry_id}"
        rows[entry_id] = visible_text(matches[0])
        entry = stored[entry_id]
        assert entry.dataset_id in rows[entry_id], (
            f"Missing or incorrect evaluation dataset for {entry_id}"
        )
        if entry.training_dataset_id:
            assert entry.training_dataset_id in rows[entry_id], (
                f"Missing or incorrect training dataset for {entry_id}"
            )
    same_id = evaluations[case.training_dataset_id]["recorded"]["entry_id"]
    assert re.search(r"樣本內|in.sample", rows[same_id], re.IGNORECASE)
    other_id = evaluations[case.overlapping_dataset_id]["recorded"]["entry_id"]
    assert re.search(r"重疊|無法|不能|不足|不代表|不等於|樣本內", rows[other_id])
    for entry in case.historical:
        if entry.producer_source is ProducerSource.CALLER_ARRAY:
            row = rows[entry.entry_id]
            assert re.search(r"呼叫端|外部|自備|caller", row, re.IGNORECASE), (
                "Caller series must be described as externally supplied"
            )
            assert re.search(r"宣告|標籤|不能|無法|不代表|不證明|未驗證", row), (
                "Caller model label must not be treated as verified signal origin"
            )
            _reject_unsupported_sample_claims(row)
            continue
        row = rows[entry.entry_id]
        _require_unknown_sample_provenance([row])
        assert re.search(r"訊號|產生|來源", row) and re.search(
            r"未知|不明|未記錄|未保存|無法", row
        ), "Historical signal origin must remain unknown"
    print(
        "[training-provenance] Final reply for semantic review:\n" + final_text,
        flush=True,
    )


@pytest.mark.live_llm
def test_natural_request_interprets_training_provenance(
    pytestconfig: pytest.Config,
) -> None:
    with temporary_mcp_workspace() as workspace:
        case = asyncio.run(prepare_training_provenance(workspace))
        turns: list[ModelTurn] = []
        readonly_tools: set[str] = set()

        async def observe_final(turn: ModelTurn) -> None:
            turns.append(turn)

        async def run() -> list[ToolCall]:
            options: dict[str, Any] = {
                "timeout_seconds": pytestconfig.getoption("llm_timeout"),
                "model": pytestconfig.getoption("llm_model"),
                "reasoning_effort": pytestconfig.getoption("llm_reasoning_effort"),
                "user_reply": observe_final,
                "max_tool_calls": 24,
            }
            async with workspace.connect() as client:
                product_tools = (await client.session.list_tools()).tools
                names = [tool.name for tool in product_tools]
                readonly_tools.update(
                    tool.name
                    for tool in product_tools
                    if tool.annotations and tool.annotations.read_only_hint is True
                )
                assert all(name not in case.request for name in names)
                options["tool_names"] = names
                if pytestconfig.getoption("llm_provider") == "local":
                    return await run_local_model(
                        client,
                        case.request,
                        base_url=pytestconfig.getoption("llm_base_url"),
                        temperature=pytestconfig.getoption("llm_temperature"),
                        **options,
                    )
            return codex_calls(await run_codex(workspace.root, case.request, **options))

        calls = asyncio.run(run())
        print(
            json.dumps([asdict(call) for call in calls], ensure_ascii=False), flush=True
        )
        assert len(turns) == 1
        assert_training_provenance(
            workspace, case, calls, turns[0].text, readonly_tools
        )
    assert not workspace.root.exists()


@pytest.mark.live_llm
def test_llm_ml_pipeline(pytestconfig: pytest.Config) -> None:
    provider = pytestconfig.getoption("llm_provider")
    assert provider in {"codex", "local"}, "Use scripts/check-llm.sh codex|local"
    with temporary_mcp_workspace() as workspace:
        seed_ml_markets(workspace)
        turns: list[ModelTurn] = []

        async def observe_final(turn: ModelTurn) -> None:
            turns.append(turn)

        async def run() -> list[ToolCall]:
            options: dict[str, Any] = {
                "timeout_seconds": pytestconfig.getoption("llm_timeout"),
                "model": pytestconfig.getoption("llm_model"),
                "reasoning_effort": pytestconfig.getoption("llm_reasoning_effort"),
                "tool_names": ML_TOOLS,
                "user_reply": observe_final,
                "max_tool_calls": 16,
            }
            if provider == "codex":
                return codex_calls(
                    await run_codex(workspace.root, ML_PROMPT, **options)
                )
            async with workspace.connect() as client:
                return await run_local_model(
                    client,
                    ML_PROMPT,
                    base_url=pytestconfig.getoption("llm_base_url"),
                    temperature=pytestconfig.getoption("llm_temperature"),
                    **options,
                )

        calls = asyncio.run(run())
        transcript = {
            "calls": [asdict(call) for call in calls],
            "turns": [asdict(turn) for turn in turns],
        }
        (workspace.root / "ml-transcript.json").write_text(
            json.dumps(transcript, ensure_ascii=False, indent=2), encoding="utf-8"
        )
        try:
            evidence = assert_ml_workflow(calls)
            assert_ml_artifacts(workspace, evidence)
            assert len(turns) == 1
            assert IN_SAMPLE_STATEMENT in turns[0].text
            assert VALIDATION_STATEMENT in turns[0].text
            for identifier in (
                evidence.dataset["dataset_id"],
                evidence.model["model_id"],
                evidence.evaluation["recorded"]["entry_id"],
            ):
                assert identifier in turns[0].text
        except AssertionError as error:
            pytest.fail(
                f"Incomplete {provider}/ML workflow: {error}\n"
                + json.dumps(transcript, ensure_ascii=False)
            )


@pytest.mark.live_llm
def test_natural_request_discovers_rule_and_repairs_threshold(
    pytestconfig: pytest.Config,
) -> None:
    with temporary_mcp_workspace() as workspace:
        seed_ml_markets(workspace)
        paths = WorkspacePaths(workspace.workspace)

        async def prepare() -> dict[str, Any]:
            async with workspace.connect() as client:
                result = await client.call(
                    "build_dataset", **{**DATASET_ARGUMENTS, "feature_set": "technical"}
                )
                assert result["success"], result
                dataset: dict[str, Any] = result["dataset"]
                return dataset

        dataset = asyncio.run(prepare())
        request = (
            f"請使用已保存的資料集 {dataset['dataset_id']}，研究 RSI14 低於 150 時"
            "偏多、否則偏空的手設訊號，評估並保存結果。若無法評估，請說明原因，"
            "等我提供新門檻，不要自行改設定。這次只做訊號研究，不訓練模型或執行回測。"
        )
        correction = (
            "改成 RSI14 低於 50 時偏多、否則偏空，沿用同一資料集，評估並保存。"
            "最後只列出手設規則的候選排名，說明訊號模擬的持倉限制及保存結果的識別碼。"
        )
        turns: list[ModelTurn] = []
        # Saving requested research includes failure notes and their delivery;
        # unrelated model/strategy/execution writes remain forbidden.
        permitted = {
            "evaluate_signal",
            "save_research_note",
            "export_research_note",
            "generate_report",
        }

        async def reply(turn: ModelTurn) -> str | None:
            turns.append(turn)
            print(
                f"[rule-research] Turn {len(turns)} for semantic review:\n{turn.text}",
                flush=True,
            )
            if len(turns) == 1:
                for call in turn.calls:
                    if call.name == "evaluate_signal":
                        assert call.arguments.get("threshold") == 150
                        assert call.arguments.get("direction") == "below"
                        assert call.arguments.get("column") == "rsi_14"
                        assert call.arguments.get("dataset_id") == dataset["dataset_id"]
                        assert not call.arguments.get("model_id")
                assert not LeaderboardStore(paths.ml_leaderboard).entries(), (
                    "The unsupported threshold must not save a candidate"
                )
                return correction
            return None

        async def run() -> list[ToolCall]:
            options: dict[str, Any] = {
                "timeout_seconds": pytestconfig.getoption("llm_timeout"),
                "model": pytestconfig.getoption("llm_model"),
                "reasoning_effort": pytestconfig.getoption("llm_reasoning_effort"),
                "user_reply": reply,
                "max_tool_calls": 18,
            }
            async with workspace.connect() as client:
                tools = (await client.session.list_tools()).tools
                names = [tool.name for tool in tools]
                permitted.update(
                    tool.name
                    for tool in tools
                    if tool.annotations and tool.annotations.read_only_hint is True
                )
                assert all(name not in request + correction for name in names)
                options["tool_names"] = names
                if pytestconfig.getoption("llm_provider") == "local":
                    return await run_local_model(
                        client,
                        request,
                        base_url=pytestconfig.getoption("llm_base_url"),
                        temperature=pytestconfig.getoption("llm_temperature"),
                        **options,
                    )
            return codex_calls(await run_codex(workspace.root, request, **options))

        calls = asyncio.run(run())
        assert len(turns) == 2
        assert all(call.name in permitted for call in calls), calls
        evaluated = [
            call
            for call in effective_workflow_calls(calls)
            if call.name == "evaluate_signal" and call.result.get("success")
        ]
        assert evaluated and all(
            call.arguments.get("threshold") == 50
            and call.arguments.get("direction") == "below"
            and call.arguments.get("column") == "rsi_14"
            and call.arguments.get("dataset_id") == dataset["dataset_id"]
            for call in evaluated
        )
        assert all(
            call.result.get("producer_source") == "backend_rule"
            and call.result["recorded"].get("producer_source") == "backend_rule"
            for call in evaluated
        )
        entries = LeaderboardStore(paths.ml_leaderboard).entries()
        assert len(entries) == 1
        entry = entries[0]
        frame, _ = MLDatasetStore(paths.ml_datasets).load(dataset["dataset_id"])
        signal = np.where(frame["rsi_14"] < 50, 1.0, -1.0)
        assert entry.family == "rule" and entry.parameters == {"threshold": 50.0}
        assert entry.producer_source is ProducerSource.BACKEND_RULE
        assert entry.signal_fingerprint == signal_fingerprint(signal.tolist())
        ranked = [
            call
            for call in calls
            if call.name == "leaderboard"
            and call.arguments.get("family") == "rule"
            and call.result.get("success")
        ]
        assert ranked and ranked[-1].result["families"] == {"rule": 1}
        assert ranked[-1].result["ranked"][0].get("producer_source") == "backend_rule"
        assert entry.entry_id in turns[-1].text
    assert not workspace.root.exists()


@pytest.mark.live_llm
def test_natural_request_discovers_saved_ml_report(pytestconfig: pytest.Config) -> None:
    provider = pytestconfig.getoption("llm_provider")
    assert provider in {"codex", "local"}, "Use scripts/check-llm.sh codex|local"
    with temporary_mcp_workspace() as workspace:
        entries = seed_ml_report_candidates(WorkspacePaths(workspace.workspace))
        turns: list[ModelTurn] = []
        observed_calls: list[ToolCall] = []

        async def observe_final(turn: ModelTurn) -> None:
            turns.append(turn)

        async def run() -> list[ToolCall]:
            options: dict[str, Any] = {
                "timeout_seconds": pytestconfig.getoption("llm_timeout"),
                "model": pytestconfig.getoption("llm_model"),
                "reasoning_effort": pytestconfig.getoption("llm_reasoning_effort"),
                "user_reply": observe_final,
                "max_tool_calls": 18,
                "on_tool_call": observed_calls.append,
            }
            async with workspace.connect() as client:
                names = list(client.output_schemas)
                assert all(name not in ML_REPORT_REQUEST for name in names), (
                    "Natural user request must not supply tool names"
                )
                print(
                    f"[ml-report] Complete product tool set: {len(names)}",
                    flush=True,
                )
                options["tool_names"] = names
                if provider == "local":
                    return await run_local_model(
                        client,
                        ML_REPORT_REQUEST,
                        base_url=pytestconfig.getoption("llm_base_url"),
                        temperature=pytestconfig.getoption("llm_temperature"),
                        **options,
                    )
            return codex_calls(
                await run_codex(workspace.root, ML_REPORT_REQUEST, **options)
            )

        try:
            calls = asyncio.run(run())
        except Exception as error:
            error.add_note(
                "ML report calls before model failure:\n"
                + json.dumps(
                    [asdict(call) for call in observed_calls], ensure_ascii=False
                )
            )
            raise
        transcript = {
            "calls": [asdict(call) for call in calls],
            "turns": [asdict(turn) for turn in turns],
        }
        (workspace.root / "ml-report-transcript.json").write_text(
            json.dumps(transcript, ensure_ascii=False, indent=2), encoding="utf-8"
        )
        try:
            assert len(turns) == 1, "Saved research already provides report inputs"
            verify_ml_report_outcome(workspace, calls, turns[0], entries)
        except (AssertionError, KeyError, ValueError, IndexError) as error:
            pytest.fail(
                f"Incomplete {provider}/ML report discovery: {error}\n"
                + json.dumps(transcript, ensure_ascii=False)
            )
    assert not workspace.root.exists()


@pytest.mark.live_llm
def test_natural_request_discovers_rolling_evidence(
    pytestconfig: pytest.Config,
) -> None:
    """Discover both the scheme menu and saved per-roll evidence without a script."""
    request = (
        "請說明這套系統的滾動重訓有哪些視窗方案，固定長度與持續擴大有何差別。"
        "另外請查已保存的結果 rolling_saved，解釋實際嘗試與成功重訓幾次、"
        "第 2 次嘗試用了多少筆已標記樣本，並說明完整證據保存在哪裡。"
        "只查已有資料，不要重新訓練、回測或修改策略。"
    )
    with temporary_mcp_workspace() as workspace:
        paths = WorkspacePaths(workspace.workspace)
        store = SQLiteStore(paths)
        trace = {
            "scheme": "roll_ex",
            "rtype": "ROLL_EX",
            "step": 5,
            "window_size": None,
            "min_train_bars": 55,
            "predict_lookback": 24,
            "label_horizon": 1,
            "bars": 17,
            "bars_scored": 12,
            "initial_model_available": False,
            "unscored_bars": list(range(5)),
            "rolls": [
                {
                    "index": i,
                    "retrain_bar": 5 * i,
                    "train_start": 0,
                    "train_end": 53 + 5 * i,
                    "test_start": 5 * i,
                    "test_end": min(17, 5 * (i + 1)),
                    "n_train_rows": 52 + 5 * i,
                    "trained": i > 0,
                    "bars_scored": 0 if i == 0 else min(5, 17 - 5 * i),
                }
                for i in range(4)
            ],
        }
        _publish(
            (paths, store, RunService(workspace=paths, store=store)),
            "rolling_saved",
            scopes={
                "fold/0/test": _scope(split="test", metadata={"rolling_trace": trace})
            },
            default_scope="fold/0/test",
        )
        turns: list[ModelTurn] = []
        readonly_tools: set[str] = set()

        async def observe_final(turn: ModelTurn) -> None:
            turns.append(turn)

        async def run() -> list[ToolCall]:
            options: dict[str, Any] = {
                "timeout_seconds": pytestconfig.getoption("llm_timeout"),
                "model": pytestconfig.getoption("llm_model"),
                "reasoning_effort": pytestconfig.getoption("llm_reasoning_effort"),
                "user_reply": observe_final,
            }
            async with workspace.connect() as client:
                tools = (await client.session.list_tools()).tools
                names = [tool.name for tool in tools]
                readonly_tools.update(
                    tool.name
                    for tool in tools
                    if tool.annotations is not None
                    and tool.annotations.read_only_hint is True
                )
                assert all(name not in request for name in names)
                options["tool_names"] = names
                if pytestconfig.getoption("llm_provider") == "local":
                    return await run_local_model(
                        client,
                        request,
                        base_url=pytestconfig.getoption("llm_base_url"),
                        temperature=pytestconfig.getoption("llm_temperature"),
                        **options,
                    )
            return codex_calls(await run_codex(workspace.root, request, **options))

        attempted = asyncio.run(run())
        transcript = {
            "calls": [asdict(call) for call in attempted],
            "turns": [asdict(turn) for turn in turns],
        }
        try:
            assert all(call.name in readonly_tools for call in attempted), attempted
            artifact = store.get_artifact("rolling_saved:performance_json")
            assert artifact is not None
            assert turns
            verify_rolling_evidence(
                attempted, turns[-1].text, Path(artifact["path"]).read_text()
            )
        except (AssertionError, KeyError, ValueError, IndexError) as error:
            pytest.fail(
                f"Incomplete rolling evidence: {error}\n"
                + json.dumps(transcript, ensure_ascii=False)
            )
        print(
            "[rolling-evidence] Final reply for semantic review:\n" + turns[-1].text,
            flush=True,
        )
    assert not workspace.root.exists()


def verify_rolling_evidence(
    attempted: list[ToolCall], reply: str, saved_text: str
) -> None:
    """Accept a bound summary plus detail, or complete saved artifact evidence."""
    calls = effective_workflow_calls(attempted)
    assert any(c.name == "get_ml_contract" and c.result.get("success") for c in calls)
    summaries = [
        c.result.get("metadata", {}).get("rolling_trace", {})
        for c in calls
        if c.name == "get_run_metrics"
        and c.result.get("success")
        and c.arguments.get("run_id") == "rolling_saved"
        and c.result.get("scope") == "fold/0/test"
    ]
    summary = any(
        item.get("roll_count") == 4
        and item.get("trained_roll_count") == 3
        and item.get("artifact_id") == "rolling_saved:performance_json"
        for item in summaries
    )
    covered = bytearray(len(saved_text))
    contents: list[str] = []
    for call in calls:
        if not (
            call.name == "get_artifact"
            and call.result.get("success")
            and call.arguments.get("artifact_id") == "rolling_saved:performance_json"
            and "content" in call.result
            and "content_page" in call.result
        ):
            continue
        assert (
            call.result["artifact"]["artifact_id"] == "rolling_saved:performance_json"
        )
        page = call.result["content_page"]
        content = call.result["content"]
        offset = page["offset"]
        assert page["total_characters"] == len(saved_text)
        assert page["content_sha256"] == hashlib.sha256(saved_text.encode()).hexdigest()
        assert 0 <= offset <= offset + len(content) <= len(saved_text)
        assert content == saved_text[offset : offset + len(content)]
        covered[offset : offset + len(content)] = b"1" * len(content)
        contents.append(content)
    observed_text = "".join(
        character if covered[index] else "\0"
        for index, character in enumerate(saved_text)
    )
    assert contents and re.search(r'"n_train_rows"\s*:\s*57\b', observed_text), (
        "Read the second roll's saved labeled-row count"
    )
    assert summary or (covered and all(covered)), (
        "Read bound roll counts or the complete saved trace"
    )
    prose = visible_text(reply)
    assert all(re.search(rf"(?<!\d){number}(?!\d)", prose) for number in (4, 3, 57)), (
        "Explain all requested roll counts"
    )
    assert "rolling_saved" in prose, "Identify the saved evidence in the final reply"

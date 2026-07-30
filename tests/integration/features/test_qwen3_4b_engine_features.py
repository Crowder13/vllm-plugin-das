# SPDX-License-Identifier: Apache-2.0
# SPDX-FileCopyrightText: Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""Single-HCU engine feature smoke coverage with a small Qwen3 model."""

from __future__ import annotations

from typing import Any

import pytest

from tests.fixtures.resources import TestResources as HcuTestResources
from tests.integration.model_runtime import require_model_runtime, run_vllm_case


QWEN3_4B = "qwen3/Qwen3-4B"

pytestmark = [
    pytest.mark.hcu,
    pytest.mark.model,
    pytest.mark.hcu_count(1),
    pytest.mark.slow,
]


def _feature_model(resources: HcuTestResources):
    return require_model_runtime(
        resources,
        env_name="VLLM_HCU_ENGINE_FEATURE_MODEL",
        relative_path=QWEN3_4B,
        label="Qwen3-4B engine feature",
    )


def _assert_generation(record: dict[str, Any], *, max_tokens: int) -> None:
    assert record["prompt_token_count"] > 0
    assert 1 <= len(record["token_ids"]) <= max_tokens
    assert record["finish_reason"] in {"length", "stop", "eos"}


def test_qwen3_4b_engine_features_prefix_caching(
    hcu_test_resources: HcuTestResources,
) -> None:
    model_path = _feature_model(hcu_test_resources)

    result = run_vllm_case(
        "prefix-caching-smoke",
        model_path,
        timeout_s=1800,
    )

    assert result["enable_prefix_caching"] is True
    assert len(result["first"]) == 2
    assert len(result["second"]) == 2
    assert [item["token_ids"] for item in result["first"]] == [
        item["token_ids"] for item in result["second"]
    ]
    for record in [*result["first"], *result["second"]]:
        _assert_generation(record, max_tokens=6)


def test_qwen3_4b_engine_features_chunked_prefill(
    hcu_test_resources: HcuTestResources,
) -> None:
    model_path = _feature_model(hcu_test_resources)

    result = run_vllm_case(
        "chunked-prefill-smoke",
        model_path,
        timeout_s=1800,
    )

    assert result["enable_chunked_prefill"] is True
    assert len(result["output"]) == 1
    assert result["output"][0]["prompt_token_count"] > 256
    _assert_generation(result["output"][0], max_tokens=4)


def test_qwen3_4b_engine_features_logprobs(
    hcu_test_resources: HcuTestResources,
) -> None:
    model_path = _feature_model(hcu_test_resources)

    result = run_vllm_case(
        "logprobs-smoke",
        model_path,
        timeout_s=1800,
    )

    assert len(result["output"]) == 1
    record = result["output"][0]
    _assert_generation(record, max_tokens=5)
    assert record["sample_logprob_count"] == len(record["token_ids"])
    assert record["sample_top_logprob_count"] >= len(record["token_ids"])
    assert record["prompt_logprob_count"] > 0
    assert record["prompt_top_logprob_count"] >= record["prompt_logprob_count"]


def test_qwen3_4b_engine_features_batch_mixed_lengths(
    hcu_test_resources: HcuTestResources,
) -> None:
    model_path = _feature_model(hcu_test_resources)

    result = run_vllm_case(
        "batch-mixed-lengths",
        model_path,
        timeout_s=1800,
    )

    assert result["prompt_count"] == 4
    assert len(result["output"]) == 4
    prompt_lengths = [record["prompt_token_count"] for record in result["output"]]
    assert prompt_lengths[0] < prompt_lengths[1] < prompt_lengths[2]
    assert len(set(prompt_lengths)) >= 3
    for record in result["output"]:
        _assert_generation(record, max_tokens=6)

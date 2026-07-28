# SPDX-License-Identifier: Apache-2.0
# SPDX-FileCopyrightText: Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""Eager versus graph-enabled generation parity on a real small model."""

from __future__ import annotations

import pytest

from tests.fixtures.resources import TestResources as HcuTestResources
from tests.integration.model_runtime import require_model_runtime, run_vllm_case


QWEN35_9B = "qwen3.5/Qwen3.5-9B"

pytestmark = [
    pytest.mark.hcu,
    pytest.mark.model,
    pytest.mark.hcu_count(1),
]


def test_qwen35_9b_eager_graph_token_parity(
    hcu_test_resources: HcuTestResources,
) -> None:
    model_path = require_model_runtime(
        hcu_test_resources,
        env_name="VLLM_HCU_GRAPH_MODEL",
        relative_path=QWEN35_9B,
        label="Qwen3.5-9B graph",
    )
    result = run_vllm_case("graph-parity", model_path, timeout_s=2400)

    eager_tokens = [item["token_ids"] for item in result["eager"]]
    graph_tokens = [item["token_ids"] for item in result["graph"]]
    assert graph_tokens == eager_tokens
    assert all(tokens for tokens in graph_tokens)

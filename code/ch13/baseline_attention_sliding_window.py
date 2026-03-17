"""baseline_attention_sliding_window.py - Dense masked sliding-window attention baseline."""

from __future__ import annotations

import torch

from core.benchmark.flexattention_sliding_window import (
    SlidingWindowAttentionBenchmark,
    SlidingWindowConfig,
)
from core.harness.benchmark_harness import BaseBenchmark


class BaselineSlidingWindowAttentionBenchmark(SlidingWindowAttentionBenchmark):
    def __init__(self) -> None:
        cfg = SlidingWindowConfig(
            batch_size=2,
            num_heads=16,
            seq_len=2048,
            head_dim=64,
            window_size=256,
            dtype=torch.bfloat16,
        )
        super().__init__(use_flex=False, cfg=cfg)


def get_benchmark() -> BaseBenchmark:
    return BaselineSlidingWindowAttentionBenchmark()



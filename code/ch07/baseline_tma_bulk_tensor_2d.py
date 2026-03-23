"""Python harness wrapper for baseline_tma_bulk_tensor_2d.cu."""

from __future__ import annotations
from typing import Optional

from pathlib import Path

from core.benchmark.cuda_binary_benchmark import CudaBinaryBenchmark


class BaselineTMABulkTensor2D(CudaBinaryBenchmark):
    """Wraps the manual 2D bulk copy (no TMA)."""

    def __init__(self) -> None:
        chapter_dir = Path(__file__).parent
        width = 2048
        height = 2048
        tile_m = 128
        tile_n = 64
        bytes_per_matrix = width * height * 4
        super().__init__(
            chapter_dir=chapter_dir,
            binary_name="baseline_tma_bulk_tensor_2d",
            friendly_name="Baseline Tma Bulk Tensor 2D",
            iterations=3,
            warmup=5,
            timeout_seconds=120,
            workload_params={
                "width": width,
                "height": height,
                "tile_m": tile_m,
                "tile_n": tile_n,
                "dtype": "float32",
            },
        )
        self.register_workload_metadata(bytes_per_iteration=float(bytes_per_matrix * 2))

    def get_custom_metrics(self) -> Optional[dict]:
        """Return memory access metrics."""
        return None

def get_benchmark() -> BaselineTMABulkTensor2D:
    """Factory for discover_benchmarks()."""
    return BaselineTMABulkTensor2D()

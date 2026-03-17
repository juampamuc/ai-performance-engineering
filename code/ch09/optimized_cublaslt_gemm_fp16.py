"""Python harness wrapper for optimized_cublaslt_gemm_fp16.cu."""

from __future__ import annotations
from typing import Optional

from pathlib import Path

from core.harness.benchmark_harness import BaseBenchmark
from core.benchmark.cuda_binary_benchmark import CudaBinaryBenchmark


class OptimizedCublasltGemmFp16Benchmark(CudaBinaryBenchmark):
    """Wraps the optimized CUDA binary."""

    def __init__(self) -> None:
        chapter_dir = Path(__file__).parent
        super().__init__(
            chapter_dir=chapter_dir,
            binary_name="optimized_cublaslt_gemm_fp16",
            friendly_name="Optimized Cublaslt Gemm Fp16",
            iterations=1,
            warmup=5,
            timeout_seconds=180,
            workload_params={
                "M": 2048,
                "N": 2048,
                "K": 2048,
                "kIterations": 10,
                "kBatchCount": 64,
                "dtype": "float16",
            },
        )

    def get_custom_metrics(self) -> Optional[dict]:
        return None


def get_benchmark() -> BaseBenchmark:
    return OptimizedCublasltGemmFp16Benchmark()



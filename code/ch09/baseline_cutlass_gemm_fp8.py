"""Python harness wrapper for baseline_cutlass_gemm_fp8.cu."""

from __future__ import annotations
from typing import Optional

from pathlib import Path

from core.harness.benchmark_harness import BaseBenchmark
from core.benchmark.cuda_binary_benchmark import CudaBinaryBenchmark


class BaselineCutlassGemmFp8Benchmark(CudaBinaryBenchmark):
    """Wraps the baseline CUDA binary."""

    def __init__(self) -> None:
        chapter_dir = Path(__file__).parent
        super().__init__(
            chapter_dir=chapter_dir,
            binary_name="baseline_cutlass_gemm_fp8",
            friendly_name="Baseline Cutlass Gemm Fp8",
            iterations=1,
            warmup=5,
            timeout_seconds=180,
            workload_params={
                "M": 4096,
                "N": 4096,
                "K": 4096,
                "kIterations": 10,
                "kRepeats": 16,
                "dtype": "fp8_e4m3",
            },
        )
        self._selected_backend = "cutlass_sm90"

    def setup(self) -> None:
        import torch

        if not torch.cuda.is_available():
            raise RuntimeError("SKIPPED: CUDA required for CUTLASS FP8")
        major, _minor = torch.cuda.get_device_capability()
        if major == 9:
            self._selected_backend = "cutlass_sm90"
            self.binary_name = "baseline_cutlass_gemm_fp8"
            self.friendly_name = "Baseline Cutlass Gemm Fp8"
        else:
            # Portable fallback until the SM90 CUTLASS FP8 kernel is ported to SM100+.
            self._selected_backend = "cublaslt_fp8_fallback"
            self.binary_name = "baseline_cublaslt_gemm_fp8"
            self.friendly_name = "Baseline CuBLASLt Gemm Fp8 (fallback)"
        super().setup()

    def get_custom_metrics(self) -> Optional[dict]:
        return {"fp8_backend": self._selected_backend}


def get_benchmark() -> BaseBenchmark:
    return BaselineCutlassGemmFp8Benchmark()



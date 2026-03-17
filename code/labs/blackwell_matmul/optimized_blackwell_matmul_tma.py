"""Part 2: hardware feature port using shared-memory pipelines."""

from __future__ import annotations

from labs.blackwell_matmul import (
    baseline_blackwell_matmul,
    optimized_blackwell_matmul_pseudo,
    optimized_blackwell_matmul_tma,
)
from labs.blackwell_matmul.blackwell_benchmarks import (
    FeatureDescriptor,
    GraceBlackwellMatmulBenchmark,
)


class TmaGraceBlackwellBenchmark(GraceBlackwellMatmulBenchmark):
    def __init__(self, size: int = 2048) -> None:
        descriptor = FeatureDescriptor(
            tag="tma",
            notes="Part 2: real TMA path (fails fast if TMA unsupported)",
        )
        super().__init__(
            runner=optimized_blackwell_matmul_tma,
            label="grace_blackwell_matmul_tma",
            size=size,
            iterations=5,
            warmup=5,
            descriptor=descriptor,
            reference_runner=optimized_blackwell_matmul_pseudo,
        )
        self.required_capabilities = {"tma": True}

def get_benchmark() -> GraceBlackwellMatmulBenchmark:
    return TmaGraceBlackwellBenchmark()



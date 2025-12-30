"""Optimized TPOT/long-output disaggregated prefill/decode benchmark (single GPU)."""

from __future__ import annotations

from core.harness.benchmark_harness import BaseBenchmark

from ch17.baseline_prefill_decode_disagg_multigpu import PrefillDecodeConfig
from ch17.prefill_decode_disagg_single_common import PrefillDecodeSingleGPUBenchmark, attach_benchmark_metadata

TPOT_LONG_CONFIG = PrefillDecodeConfig(
    context_window=512,
    decode_tokens=1024,
)


def get_benchmark() -> BaseBenchmark:
    bench = PrefillDecodeSingleGPUBenchmark(
        use_host_staging=False,
        label="optimized_prefill_decode_disagg_tpot_long",
        cfg=TPOT_LONG_CONFIG,
    )
    return attach_benchmark_metadata(bench, __file__)


if __name__ == "__main__":
    from core.harness.benchmark_harness import benchmark_main

    benchmark_main(get_benchmark)

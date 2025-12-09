"""Optimized AI example: fuse blocks into a single inference stack without CPU sync."""

from __future__ import annotations

from typing import Optional

import torch
import torch.nn as nn

from core.harness.benchmark_harness import BaseBenchmark, BenchmarkConfig, WorkloadMetadata
from core.utils.compile_utils import enable_tf32


class TinyBlock(nn.Module):
    """Same architecture as baseline for fair comparison."""
    def __init__(self, hidden_dim: int):
        super().__init__()
        self.linear1 = nn.Linear(hidden_dim, hidden_dim * 2)
        self.relu = nn.ReLU()
        self.linear2 = nn.Linear(hidden_dim * 2, hidden_dim)

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        return self.linear2(self.relu(self.linear1(x)))


class OptimizedAIBenchmark(BaseBenchmark):
    """Chains the tiny blocks without CPU sync between them (the optimization)."""

    def __init__(self):
        super().__init__()
        self.blocks: Optional[nn.ModuleList] = None
        self.static_input: Optional[torch.Tensor] = None
        self.output: Optional[torch.Tensor] = None
        self.batch = 512
        self.hidden = 1024
        # Inference benchmark - jitter check not applicable
        self.jitter_exemption_reason = "Inference benchmark: fixed input shape"
        tokens = self.batch * self.hidden
        self._workload = WorkloadMetadata(
            requests_per_iteration=1.0,
            tokens_per_iteration=float(tokens),
        )

    def setup(self) -> None:
        torch.manual_seed(0)
        enable_tf32()
        # Initialize model weights after seeding for deterministic comparison
        self.blocks = nn.ModuleList(TinyBlock(1024).to(self.device) for _ in range(4))
        for block in self.blocks:
            block.eval()
        # Use same dtype as baseline (float32)
        self.static_input = torch.randn(self.batch, self.hidden, device=self.device, dtype=torch.float32)
        # Warmup
        with torch.inference_mode():
            out = self.static_input
            for block in self.blocks:
                out = block(out)
        self._synchronize()

    def benchmark_fn(self) -> None:
        assert self.blocks is not None and self.static_input is not None
        with self._nvtx_range("optimized_ai"):
            # The optimization: no CPU sync between blocks
            out = self.static_input
            for block in self.blocks:
                out = block(out)
            self._synchronize()
        self.output = out.detach()

    def teardown(self) -> None:
        self.static_input = None
        torch.cuda.empty_cache()

    def get_config(self) -> BenchmarkConfig:
        return BenchmarkConfig(iterations=40, warmup=5)

    def get_workload_metadata(self) -> Optional[WorkloadMetadata]:
        return self._workload

    def get_custom_metrics(self) -> Optional[dict]:
        """Return domain-specific metrics using standardized helper."""
        from core.benchmark.metrics import compute_storage_io_metrics
        return compute_storage_io_metrics(
            bytes_read=getattr(self, '_bytes_read', 0.0),
            bytes_written=getattr(self, '_bytes_written', 0.0),
            read_time_ms=getattr(self, '_read_time_ms', 1.0),
            write_time_ms=getattr(self, '_write_time_ms', 1.0),
        )

    def validate_result(self) -> Optional[str]:
        if self.blocks is None or self.static_input is None:
            return "Model/input not initialized"
        return None

    def get_input_signature(self) -> dict:
        """Return workload signature for input verification."""
        return {
            "batch": self.batch,
            "hidden": self.hidden,
        }

    def get_verify_output(self) -> torch.Tensor:
        """Return output tensor for verification comparison."""
        if self.output is not None:
            return self.output.detach().clone()
        return torch.tensor([0.0], dtype=torch.float32, device=self.device)
    
    def get_output_tolerance(self) -> tuple:
        """Return custom tolerance for inference benchmark."""
        return (1e-3, 1e-3)



def get_benchmark() -> BaseBenchmark:
    return OptimizedAIBenchmark()

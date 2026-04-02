###############################################################################
# Copyright (c) 2025, Advanced Micro Devices, Inc. All rights reserved.
#
# Licensed under the Apache License, Version 2.0
###############################################################################

import subprocess
import sys
import textwrap
from unittest.mock import patch

import pytest
import torch

DEVICE = "cuda"
_CUDA = pytest.mark.skipif(not torch.cuda.is_available(), reason="CUDA required")


# ── Pure-PyTorch references (test-only) ─────────────────────────────────────


def _topk_softmax_reference(logits, k, softmax_first=True):
    """Reference: softmax then top-k selection."""
    if softmax_first:
        probs = torch.softmax(logits.float(), dim=-1)
    else:
        probs = logits.float()
    weights, indices = probs.topk(k, dim=-1)
    weights = weights / weights.sum(dim=-1, keepdim=True)
    return weights, indices


def _permute_reference(tokens, indices, num_experts):
    """Reference: gather tokens by expert, return sort order."""
    num_tokens, k = indices.shape
    flat_indices = indices.reshape(-1)
    expert_order = torch.argsort(flat_indices, stable=True)
    token_ids = torch.arange(num_tokens, device=tokens.device).unsqueeze(1).expand(-1, k).reshape(-1)
    sorted_token_ids = token_ids[expert_order]
    return sorted_token_ids, expert_order


def _unpermute_reference(expert_output, sort_order, num_tokens, k):
    """Reference: unsort and average across top-k experts."""
    hidden_size = expert_output.shape[-1]
    unsort = torch.argsort(sort_order)
    unsorted = expert_output[unsort]
    return unsorted.reshape(num_tokens, k, hidden_size).sum(dim=1)


# ── Assertion / probe tests ────────────────────────────────────────────────


class TestFusedTopKAssertions:
    """Test fused_topk AITER-only dispatch."""

    def test_requires_aiter_and_cuda(self):
        from lumen.ops.moe.fused_routing import fused_topk

        logits = torch.randn(32, 8)
        with patch("lumen.ops.moe.fused_routing._probe_aiter_moe_topk_softmax", return_value=False):
            with pytest.raises(AssertionError):
                fused_topk(logits, k=2)

    def test_rejects_cpu_tensors(self):
        from lumen.ops.moe.fused_routing import fused_topk

        logits = torch.randn(32, 8)
        with patch("lumen.ops.moe.fused_routing._probe_aiter_moe_topk_softmax", return_value=True):
            with pytest.raises(AssertionError):
                fused_topk(logits, k=2)


class TestFusedPermuteAssertions:
    """Test fused_permute AITER-only dispatch."""

    def test_requires_aiter_and_cuda(self):
        from lumen.ops.moe.fused_routing import fused_permute

        tokens = torch.randn(16, 64)
        indices = torch.zeros(16, 2, dtype=torch.long)
        weights = torch.ones(16, 2)
        with patch("lumen.ops.moe.fused_routing._probe_aiter_moe_sorting", return_value=False):
            with pytest.raises(AssertionError):
                fused_permute(tokens, indices, weights, num_experts=4)

    def test_signature_no_use_aiter_param(self):
        import inspect

        from lumen.ops.moe.fused_routing import fused_permute

        sig = inspect.signature(fused_permute)
        assert "block_size" in sig.parameters
        assert "use_aiter" not in sig.parameters


class TestFusedUnpermuteAssertions:
    """Test fused_unpermute AITER-only dispatch."""

    def test_requires_aiter_and_cuda(self):
        from lumen.ops.moe.fused_routing import fused_unpermute

        expert_output = torch.randn(32, 64)
        sort_order = torch.arange(32)
        with patch("lumen.ops.moe.fused_routing._probe_aiter_moe_sum", return_value=False):
            with pytest.raises(AssertionError):
                fused_unpermute(expert_output, sort_order, num_tokens=16, k=2)


class TestAiterProbes:
    """Verify probe functions return bool."""

    def test_routing_probes_return_bool(self):
        from lumen.ops.dispatch import (
            _probe_aiter_moe_sorting,
            _probe_aiter_moe_sum,
            _probe_aiter_moe_topk_softmax,
        )

        assert isinstance(_probe_aiter_moe_topk_softmax(), bool)
        assert isinstance(_probe_aiter_moe_sorting(), bool)
        assert isinstance(_probe_aiter_moe_sum(), bool)

    def test_triton_moe_probes_return_bool(self):
        from lumen.ops.dispatch import (
            _probe_aiter_triton_fused_moe,
            _probe_aiter_triton_moe_align,
        )

        assert isinstance(_probe_aiter_triton_moe_align(), bool)
        assert isinstance(_probe_aiter_triton_fused_moe(), bool)


# ── Numerical correctness tests (require CUDA + AITER) ─────────────────────


@_CUDA
class TestFusedTopKCorrectness:
    """Numerical correctness for fused_topk."""

    @pytest.mark.parametrize(
        "num_tokens,num_experts,k",
        [
            (16, 8, 2),
            (64, 4, 1),
            (32, 16, 4),
        ],
    )
    def test_matches_reference(self, num_tokens, num_experts, k):
        from lumen.ops.moe.fused_routing import fused_topk

        logits = torch.randn(num_tokens, num_experts, device=DEVICE, dtype=torch.float32)
        weights, indices = fused_topk(logits, k=k)
        ref_weights, ref_indices = _topk_softmax_reference(logits, k)

        assert weights.shape == (num_tokens, k)
        assert indices.shape == (num_tokens, k)

        for i in range(num_tokens):
            actual_set = set(indices[i].tolist())
            expected_set = set(ref_indices[i].tolist())
            assert actual_set == expected_set, f"Token {i}: got experts {actual_set}, expected {expected_set}"

        actual_sorted = torch.sort(indices, dim=-1)
        ref_sorted = torch.sort(ref_indices, dim=-1)
        torch.testing.assert_close(
            weights.gather(1, actual_sorted.indices),
            ref_weights.gather(1, ref_sorted.indices),
            atol=1e-4,
            rtol=1e-4,
        )

    def test_weights_sum_to_one(self):
        from lumen.ops.moe.fused_routing import fused_topk

        logits = torch.randn(64, 8, device=DEVICE, dtype=torch.float32)
        weights, _ = fused_topk(logits, k=2)

        row_sums = weights.sum(dim=-1)
        torch.testing.assert_close(
            row_sums,
            torch.ones_like(row_sums),
            atol=1e-5,
            rtol=1e-5,
        )

    def test_weights_are_positive(self):
        from lumen.ops.moe.fused_routing import fused_topk

        logits = torch.randn(32, 8, device=DEVICE)
        weights, _ = fused_topk(logits, k=2)
        assert (weights > 0).all()

    def test_indices_in_range(self):
        from lumen.ops.moe.fused_routing import fused_topk

        num_experts = 8
        logits = torch.randn(32, num_experts, device=DEVICE)
        _, indices = fused_topk(logits, k=2)
        assert (indices >= 0).all()
        assert (indices < num_experts).all()


@_CUDA
class TestFusedTopKSoftmaxFirst:
    """Test softmax_first=False path."""

    def test_softmax_first_false(self):
        """With softmax_first=False, top-k selects on raw logits (no renorm)."""
        from lumen.ops.moe.fused_routing import fused_topk

        logits = torch.randn(16, 8, device=DEVICE, dtype=torch.float32)
        weights_false, indices_false = fused_topk(logits, k=2, softmax_first=False)

        assert weights_false.shape == (16, 2)
        assert indices_false.shape == (16, 2)
        assert (indices_false >= 0).all() and (indices_false < 8).all()
        # softmax_first=False → AITER does NOT apply softmax or renorm;
        # weights are raw logit values of selected experts, not guaranteed
        # to sum to 1.  Just verify they are finite and non-negative
        # (top-k from softmax output when need_renorm=False still applies
        # softmax but skips the per-token renorm step in the kernel).
        assert weights_false.isfinite().all()
        assert (weights_false >= 0).all()


@_CUDA
class TestFusedPermuteCorrectness:
    """Numerical correctness for fused_permute.

    All tests use hidden >= 128 to avoid AITER ``moe_sorting_fwd`` HIP kernel
    crashes that occur non-deterministically with small hidden dimensions
    (e.g. 32 or 64).  The kernel's internal zero-fill of ``moe_buf`` may
    access out-of-bounds for tiny buffers.
    """

    def test_output_shapes(self):
        from lumen.ops.moe.fused_routing import fused_permute

        num_tokens, hidden, k, num_experts = 16, 128, 2, 4
        tokens = torch.randn(num_tokens, hidden, device=DEVICE)
        indices = torch.randint(0, num_experts, (num_tokens, k), device=DEVICE, dtype=torch.int64)
        weights = torch.ones(num_tokens, k, device=DEVICE)

        sorted_ids, sorted_weights, sorted_expert_ids, num_valid_ids, moe_buf = fused_permute(
            tokens, indices, weights, num_experts=num_experts
        )

        assert sorted_ids.dtype == torch.int32
        assert sorted_ids.shape == (num_tokens * k,)
        assert sorted_weights.dtype == torch.float32
        assert sorted_weights.shape == (num_tokens * k,)
        assert sorted_expert_ids.dtype == torch.int32
        assert num_valid_ids.dtype == torch.int32
        assert moe_buf.shape == (num_tokens, hidden)

    def test_all_tokens_covered(self):
        """Every token should appear in sorted output."""
        from lumen.ops.moe.fused_routing import fused_permute

        num_tokens, hidden, k, num_experts = 32, 128, 2, 8
        tokens = torch.randn(num_tokens, hidden, device=DEVICE)
        indices = torch.randint(0, num_experts, (num_tokens, k), device=DEVICE, dtype=torch.int64)
        weights = torch.ones(num_tokens, k, device=DEVICE)

        sorted_ids, sorted_weights, _, _, _ = fused_permute(tokens, indices, weights, num_experts=num_experts)

        # sorted_ids are token-major flat indices: token_id * k + slot_id
        token_ids = (sorted_ids // k).cpu()
        nonzero_mask = sorted_weights.cpu() > 0
        actual_tokens = set(token_ids[nonzero_mask].tolist())

        assert (
            len(actual_tokens) >= num_tokens
        ), f"Only {len(actual_tokens)} unique tokens found, expected >= {num_tokens}"

    def test_sorted_weights_match_input(self):
        """sorted_weights should contain the original routing weights, reordered.

        ``fused_permute`` now returns decoded flat indices
        (``token_id * k + slot_id``), so we verify directly.
        """
        from lumen.ops.moe.fused_routing import fused_permute

        num_tokens, hidden, k, num_experts = 16, 128, 2, 4
        tokens = torch.randn(num_tokens, hidden, device=DEVICE)
        indices = torch.randint(0, num_experts, (num_tokens, k), device=DEVICE, dtype=torch.int64)
        weights = torch.softmax(torch.randn(num_tokens, k, device=DEVICE), dim=-1)

        sorted_ids, sorted_weights, _, _, _ = fused_permute(tokens, indices, weights, num_experts=num_experts)

        ids_cpu = sorted_ids.cpu()
        sw_cpu = sorted_weights.cpu()
        weights_cpu = weights.float().cpu()

        matched = 0
        for i in range(ids_cpu.shape[0]):
            w = sw_cpu[i].item()
            if w == 0.0:
                continue
            flat_idx = ids_cpu[i].item()
            token_id = flat_idx // k
            slot = flat_idx % k
            assert 0 <= token_id < num_tokens, f"token_id {token_id} out of range"
            assert 0 <= slot < k, f"slot {slot} out of range"
            expected_w = weights_cpu[token_id, slot].item()
            assert abs(w - expected_w) < 1e-5, (
                f"entry {i}: weight mismatch for token={token_id} slot={slot}: " f"got {w}, expected {expected_w}"
            )
            matched += 1

        assert matched > 0, "No valid (non-zero-weight) entries found"

    def test_sorted_ids_grouped_by_expert(self):
        """Within valid range, token IDs should be grouped by expert.

        Runs in a subprocess because AITER's ``moe_sorting_fwd`` HIP kernel
        can non-deterministically SIGABRT when called after many prior
        ``fused_permute`` invocations in the same process (accumulated GPU
        state issue).  A subprocess isolates the crash so it doesn't kill
        the entire pytest session.
        """
        script = textwrap.dedent(
            """\
            import torch
            from lumen.ops.moe.fused_routing import fused_permute

            num_tokens, hidden, k, num_experts = 16, 128, 2, 4
            tokens = torch.randn(num_tokens, hidden, device="cuda")
            indices = torch.randint(0, num_experts, (num_tokens, k),
                                    device="cuda", dtype=torch.int64)
            weights = torch.ones(num_tokens, k, device="cuda")

            sorted_ids, _, sorted_expert_ids, num_valid_ids, _ = fused_permute(
                tokens, indices, weights, num_experts=num_experts
            )

            total_valid = num_valid_ids[0].item()
            block_size = 32
            num_blocks = (total_valid + block_size - 1) // block_size
            eid_cpu = sorted_expert_ids[:num_blocks].cpu()
            assert (eid_cpu >= 0).all() and (eid_cpu < num_experts).all(), (
                f"expert_ids out of range: {eid_cpu.tolist()}"
            )
        """
        )
        result = subprocess.run(
            [sys.executable, "-c", script],
            capture_output=True,
            text=True,
            timeout=60,
        )
        if result.returncode != 0:
            pytest.skip(
                f"moe_sorting_fwd kernel aborted in subprocess "
                f"(exit code {result.returncode}): {result.stderr[-500:]}"
            )

    def test_permute_unpermute_round_trip(self):
        """permute → build expert output → unpermute should recover weighted sum.

        Uses the decoded flat indices from ``fused_permute`` to build
        ``expert_output`` and feeds it through ``fused_unpermute``.

        Runs in a subprocess because repeated ``moe_sorting_fwd`` calls
        can non-deterministically crash the HIP runtime.
        """
        script = textwrap.dedent(
            """\
            import torch
            from lumen.ops.moe.fused_routing import fused_permute, fused_unpermute

            num_tokens, hidden, k, num_experts = 16, 128, 2, 4
            tokens = torch.randn(num_tokens, hidden, device="cuda", dtype=torch.float32)
            # Ensure each token routes to distinct experts to avoid
            # AITER duplicate-expert dedup.
            slot0 = torch.randint(0, num_experts, (num_tokens,), device="cuda")
            offset = torch.randint(1, num_experts, (num_tokens,), device="cuda")
            slot1 = (slot0 + offset) % num_experts
            indices = torch.stack([slot0, slot1], dim=1).to(torch.int64)
            weights = torch.softmax(
                torch.randn(num_tokens, k, device="cuda"), dim=-1)

            sorted_ids, sorted_weights, _, _, _ = fused_permute(
                tokens, indices, weights, num_experts=num_experts
            )

            # sorted_ids is decoded: flat_idx = token_id * k + slot_id
            token_ids = sorted_ids.long() // k
            expert_output = tokens[token_ids] * sorted_weights.unsqueeze(-1)

            out = fused_unpermute(expert_output, sorted_ids, num_tokens, k)

            # Reference: weighted sum across topk slots
            ref = torch.zeros(num_tokens, hidden, device="cuda")
            w_cpu = weights.cpu()
            for t in range(num_tokens):
                for s in range(k):
                    ref[t] += w_cpu[t, s].item() * tokens[t]

            maxdiff = (out - ref).abs().max().item()
            print(f"max_diff={maxdiff:.6f}")
            assert maxdiff < 1e-4, f"round-trip error too large: {maxdiff}"
        """
        )
        result = subprocess.run(
            [sys.executable, "-c", script],
            capture_output=True,
            text=True,
            timeout=60,
        )
        if result.returncode == -11:
            pytest.skip(f"moe_sorting_fwd SIGSEGV in subprocess: {result.stderr[-500:]}")
        if result.returncode != 0:
            pytest.fail(
                f"Round-trip subprocess failed (exit {result.returncode}):\n"
                f"stdout: {result.stdout}\nstderr: {result.stderr[-500:]}"
            )


@_CUDA
class TestFusedUnpermuteCorrectness:
    """Numerical correctness for fused_unpermute."""

    def test_output_shape(self):
        from lumen.ops.moe.fused_routing import fused_unpermute

        num_tokens, k, hidden = 16, 2, 128
        expert_output = torch.randn(num_tokens * k, hidden, device=DEVICE)
        sort_order = torch.randperm(num_tokens * k, device=DEVICE)

        out = fused_unpermute(expert_output, sort_order, num_tokens, k)
        assert out.shape == (num_tokens, hidden)

    def test_matches_reference_with_identity_permutation(self):
        """When sort_order is identity, moe_sum should reduce the k dim."""
        from lumen.ops.moe.fused_routing import fused_unpermute

        num_tokens, k, hidden = 8, 2, 128
        expert_output = torch.randn(num_tokens * k, hidden, device=DEVICE, dtype=torch.float32)
        sort_order = torch.arange(num_tokens * k, device=DEVICE)

        out = fused_unpermute(expert_output, sort_order, num_tokens, k)
        ref = _unpermute_reference(expert_output, sort_order, num_tokens, k)

        torch.testing.assert_close(out, ref, atol=1e-4, rtol=1e-4)

    def test_matches_reference_with_random_permutation(self):
        from lumen.ops.moe.fused_routing import fused_unpermute

        num_tokens, k, hidden = 16, 2, 128
        expert_output = torch.randn(num_tokens * k, hidden, device=DEVICE, dtype=torch.float32)
        sort_order = torch.randperm(num_tokens * k, device=DEVICE)

        out = fused_unpermute(expert_output, sort_order, num_tokens, k)
        ref = _unpermute_reference(expert_output, sort_order, num_tokens, k)

        torch.testing.assert_close(out, ref, atol=1e-4, rtol=1e-4)

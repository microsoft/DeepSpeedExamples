# SPDX-License-Identifier: Apache-2.0
# DeepSpeed Team
"""Catch direction, temperature, mask, cache and lazy-dependency regressions."""

import builtins
from dataclasses import replace

import pytest
import torch

from config import OPSDConfig
from losses import streamed_distillation_loss
from teacher import TeacherLogitCache
from vocab_parallel import VocabShardLayout


def local_layout(width):
    return VocabShardLayout(width, 0, width, (0,), ((0, width),), None)


@pytest.mark.parametrize("direction", ["forward_kl", "reverse_kl"])
@pytest.mark.parametrize("temperature", [0.5, 1.0, 2.0])
@pytest.mark.parametrize("chunk", [1, 3, 12])
def test_streamed_local_kl_matches_independent_dense_oracle(direction, temperature, chunk):
    torch.manual_seed(710)
    student = torch.randn(2, 7, 11, requires_grad=True)
    reference = student.detach().double().requires_grad_()
    teacher = torch.randn(2, 7, 11)
    mask = torch.tensor([[1, 0, 1, 1, 0, 1, 1], [0, 1, 1, 0, 1, 0, 1]], dtype=torch.float32)
    layout = local_layout(11)
    cache = TeacherLogitCache.from_gpu_logits(teacher, store_dtype=torch.bfloat16, layout=layout)
    quantized = teacher.to(torch.bfloat16).double()
    logp = torch.log_softmax(reference / temperature, dim=-1)
    logq = torch.log_softmax(quantized / temperature, dim=-1)
    tokens = (logq.exp() * (logq - logp)).sum(-1) if direction == "forward_kl" else (logp.exp() * (logp - logq)).sum(-1)
    expected = (tokens * mask).sum() * temperature**2 / mask.sum()
    result = streamed_distillation_loss(student, lambda a, b: cache.chunk_to_device(a, b, student.device),
                                       mask, loss_type=direction, temperature=temperature, chunk_size=chunk,
                                       loss_backend="vocab_parallel", vocab_layout=layout)
    result.backward()
    expected.backward()
    torch.testing.assert_close(result.double(), expected, atol=1e-6, rtol=1e-5)
    torch.testing.assert_close(student.grad.double(), reference.grad, atol=1e-6, rtol=1e-5)


def test_zero_mask_is_backward_safe_and_does_not_skip_collective_chunks():
    student = torch.randn(1, 4, 9, requires_grad=True)
    fetched = []

    def fetch(start, end):
        fetched.append((start, end))
        return torch.zeros(1, end - start, 9)

    result = streamed_distillation_loss(student, fetch, torch.zeros(1, 4), chunk_size=3,
                                       loss_backend="vocab_parallel", vocab_layout=local_layout(9))
    result.backward()
    assert result.item() == 0
    assert fetched == [(0, 3), (3, 4)]
    assert torch.count_nonzero(student.grad) == 0


def test_cache_binds_actual_width_and_rejects_use_after_free():
    with pytest.raises(ValueError, match="width"):
        TeacherLogitCache(torch.zeros(1, 3, 8), layout=local_layout(9))
    cache = TeacherLogitCache(torch.zeros(1, 3, 9), layout=local_layout(9))
    cache.free()
    with pytest.raises(RuntimeError, match="freed"):
        cache.chunk_to_device(0, 1, torch.device("cpu"))


def test_dense_does_not_import_optional_kl_dependency(monkeypatch):
    original = builtins.__import__

    def blocked(name, *args, **kwargs):
        if name == "deepspeed.sequence.vocab_parallel_ops":
            raise ImportError("dependency absent")
        return original(name, *args, **kwargs)

    monkeypatch.setattr(builtins, "__import__", blocked)
    logits = torch.randn(1, 2, 5, requires_grad=True)
    fetch = lambda a, b: torch.zeros(1, b - a, 5)
    assert torch.isfinite(streamed_distillation_loss(logits, fetch, torch.ones(1, 2)))
    with pytest.raises(RuntimeError, match="PR #8791"):
        streamed_distillation_loss(logits, fetch, torch.ones(1, 2), loss_backend="vocab_parallel",
                                    vocab_layout=local_layout(5))


def test_old_config_defaults_dense_and_opt_in_rejects_unsupported_routes():
    cfg = OPSDConfig.from_dict({"student": {"model_name_or_path": "student"},
                               "teacher": {"model_name_or_path": "teacher"}})
    assert cfg.distillation.loss_backend == "dense"
    cfg.validate()
    cfg.distillation = replace(cfg.distillation, loss_backend="vocab_parallel", loss_type="jsd")
    with pytest.raises(ValueError, match="JSD"):
        cfg.validate()
    cfg.distillation.loss_type = "reverse_kl"
    cfg.rollout.temperature = 1.0
    with pytest.raises(ValueError, match="greedy"):
        cfg.validate()
    cfg.rollout.temperature = 0.0
    cfg.validate()
    for feature in ["use_graph_capture", "use_shared_prefill"]:
        setattr(cfg.rollout, feature, True)
        with pytest.raises(ValueError, match="eager"):
            cfg.validate()
        setattr(cfg.rollout, feature, False)

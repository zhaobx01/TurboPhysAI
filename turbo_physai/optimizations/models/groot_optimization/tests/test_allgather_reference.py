# Adapted from Isaac-GR00T, SPDX-License-Identifier: Apache-2.0
from groot_optimization.zero2_allgather import (
    GroupAllGatherPipeline, launch_group_all_gather, regroup_optimizer_parameter_groups,
    regroup_torch_optimizer, describe_partition_layout,
)

def test_pipeline_overflow_clears_gradients_without_updating_or_gathering():
    from types import SimpleNamespace

    from groot_optimization.zero2_allgather import _pipeline_zero2_step

    events = []
    timer = SimpleNamespace(start=lambda: events.append("timer_start"),
                            stop=lambda: events.append("timer_stop"))
    optimizer = SimpleNamespace(
        micro_step_id=9, check_grad_overflow=True, partition_gradients=True,
        loss_scale=2.0, overflow=True,
        check_overflow=lambda **kwargs: events.append(("check_overflow", kwargs)),
        _update_scale=lambda overflow: events.append(("update_scale", overflow)),
        zero_grad=lambda **kwargs: events.append(("zero_grad", kwargs)),
        averaged_gradients={0: object(), 1: object()},
        all_grad_tensors={0: object(), 1: object()},
        timers=lambda _: timer,
    )

    _pipeline_zero2_step(optimizer)

    assert optimizer.micro_step_id != 9
    assert optimizer.averaged_gradients == {0: None, 1: None}
    assert optimizer.all_grad_tensors == {0: None, 1: None}
    assert events[:3] == [
        ("check_overflow", {"partition_gradients": True}),
        ("update_scale", True),
        ("zero_grad", {"set_to_none": True}),
    ]
    assert events.count("timer_start") == events.count("timer_stop")


def test_regroup_keeps_parameters_whole_ordered_and_hyperparameters():
    import torch

    first = [torch.nn.Parameter(torch.zeros(size)) for size in (6, 5, 2, 12)]
    second = [torch.nn.Parameter(torch.zeros(size)) for size in (4, 4)]
    groups = [
        {"params": first, "weight_decay": 0.1, "lr": 0.01, "group_name": "decay"},
        {"params": second, "weight_decay": 0.0, "lr": 0.01, "group_name": "no_decay"},
    ]

    regrouped = regroup_optimizer_parameter_groups(groups, target_elements=10)

    assert [len(group["params"]) for group in regrouped] == [1, 2, 1, 2]
    assert [param for group in regrouped for param in group["params"]] == first + second
    assert [group["group_name"] for group in regrouped] == ["decay"] * 3 + ["no_decay"]
    assert [group["weight_decay"] for group in regrouped] == [0.1] * 3 + [0.0]
    assert sum(param.numel() for group in groups for param in group["params"]) == sum(
        param.numel() for group in regrouped for param in group["params"]
    )
    assert len(groups) == 2


def test_regroup_rejects_empty_parameter_groups():
    import torch

    groups = [{"params": [torch.nn.Parameter(torch.ones(1))]}, {"params": []}]

    try:
        regroup_optimizer_parameter_groups(groups, target_elements=10)
    except ValueError as exc:
        assert "empty" in str(exc)
    else:
        raise AssertionError("empty source parameter groups must be rejected")


def test_pipeline_waits_for_all_gathers_after_all_groups_are_submitted():
    events = []

    class Work:
        def __init__(self, group_index):
            self.group_index = group_index

        def wait(self):
            events.append(("wait", self.group_index))

    pipeline = GroupAllGatherPipeline(lambda group_index: (events.append(("submit", group_index)) or Work(group_index)))
    for group_index in range(3):
        events.append(("update", group_index))
        events.append(("copy", group_index))
        pipeline.submit(group_index)

    pipeline.wait_all()
    events.append(("map_weights", None))

    assert events == [
        ("update", 0),
        ("copy", 0),
        ("submit", 0),
        ("update", 1),
        ("copy", 1),
        ("submit", 1),
        ("update", 2),
        ("copy", 2),
        ("submit", 2),
        ("wait", 0),
        ("wait", 1),
        ("wait", 2),
        ("map_weights", None),
    ]


def test_pipeline_retains_tensors_until_work_completes():
    released = []

    class Work:
        def wait(self):
            released.append("wait")

    pipeline = GroupAllGatherPipeline(lambda _: (released.append("submit") or Work()))
    tensor_refs = (object(), object())
    pipeline.submit(0, tensor_refs=tensor_refs)

    assert pipeline.in_flight_references == [tensor_refs]
    pipeline.wait_all()
    assert released == ["submit", "wait"]
    assert pipeline.in_flight_references == []


def test_pipeline_keeps_failed_work_references_for_error_cleanup():
    class Work:
        def wait(self):
            raise RuntimeError("device communication failed")

    pipeline = GroupAllGatherPipeline(lambda _: Work())
    refs = (object(), object())
    pipeline.submit(0, tensor_refs=refs)

    try:
        pipeline.wait_all()
    except RuntimeError as exc:
        assert "communication failed" in str(exc)
    else:
        raise AssertionError("failed work must propagate its error")

    assert pipeline.in_flight_references == [refs]


def test_group_gather_uses_rank_partition_alias_and_async_backend():
    import torch

    flat = torch.arange(8, dtype=torch.bfloat16)
    partitions = [flat.narrow(0, 0, 4), flat.narrow(0, 4, 4)]
    calls = []
    expected_work = object()

    class Comm:
        @staticmethod
        def get_world_size(group):
            assert group == "dp"
            return 2

        @staticmethod
        def get_rank(group):
            assert group == "dp"
            return 1

        @staticmethod
        def all_gather_into_tensor(**kwargs):
            calls.append(kwargs)
            return expected_work

    zero = type(
        "Zero",
        (),
        {
            "real_dp_process_group": ["dp"],
            "bit16_groups_flat": [flat],
            "parallel_partitioned_bit16_groups": [partitions],
        },
    )()

    request = launch_group_all_gather(zero, 0, Comm)

    assert request.work is expected_work
    assert request.output is flat
    assert request.input is partitions[1]
    assert request.input.data_ptr() == flat.narrow(0, 4, 4).data_ptr()
    assert calls == [{"output_tensor": flat, "tensor": partitions[1], "group": "dp", "async_op": True}]


def test_group_gather_rejects_nonaliased_input_partition():
    import torch

    class Comm:
        @staticmethod
        def get_world_size(group):
            return 2

        @staticmethod
        def get_rank(group):
            return 0

    zero = type(
        "Zero",
        (),
        {
            "real_dp_process_group": [None],
            "bit16_groups_flat": [torch.zeros(8, dtype=torch.bfloat16)],
            "parallel_partitioned_bit16_groups": [
                [torch.zeros(4, dtype=torch.bfloat16), torch.zeros(4, dtype=torch.bfloat16)]
            ],
        },
    )()

    try:
        launch_group_all_gather(zero, 0, Comm)
    except RuntimeError as exc:
        assert "alias" in str(exc)
    else:
        raise AssertionError("nonaliased gather storage must fail closed")


def test_partition_layout_records_offsets_padding_and_checks_equal_parts():
    import torch

    flat = torch.zeros(12, dtype=torch.bfloat16)
    parts = [flat.narrow(0, 0, 4), flat.narrow(0, 4, 4), flat.narrow(0, 8, 4)]
    params = [torch.nn.Parameter(torch.zeros(5)), torch.nn.Parameter(torch.zeros(6))]

    layout = describe_partition_layout(2, params, flat, parts, rank=1)

    assert layout == {
        "group_index": 2,
        "parameter_elements": 11,
        "flat_elements": 12,
        "padding_elements": 1,
        "partition_elements": [4, 4, 4],
        "local_partition_offset": 4,
        "local_partition_elements": 4,
    }

    unequal = [flat.narrow(0, 0, 3), flat.narrow(0, 3, 5), flat.narrow(0, 8, 4)]
    try:
        describe_partition_layout(2, params, flat, unequal, rank=1)
    except RuntimeError as exc:
        assert "equal" in str(exc)
    else:
        raise AssertionError("AllGather must reject unequal partition sizes")


def test_torch_optimizer_regroup_preserves_decay_groups_names_and_parameter_order():
    import torch

    decay = [torch.nn.Parameter(torch.ones(6)), torch.nn.Parameter(torch.ones(3))]
    no_decay = [torch.nn.Parameter(torch.ones(4)), torch.nn.Parameter(torch.ones(2))]
    optimizer = torch.optim.AdamW(
        [
            {"params": decay, "weight_decay": 0.1, "lr": 1e-4},
            {"params": no_decay, "weight_decay": 0.0, "lr": 1e-4},
        ],
        eps=1e-8,
    )
    names = {id(parameter): f"p{index}" for index, parameter in enumerate(decay + no_decay)}

    manifest = regroup_torch_optimizer(optimizer, target_elements=8, parameter_names=names)

    assert [parameter for group in optimizer.param_groups for parameter in group["params"]] == decay + no_decay
    assert [group["weight_decay"] for group in optimizer.param_groups] == [0.1, 0.1, 0.0]
    assert [entry["parameter_names"] for entry in manifest] == [["p0"], ["p1"], ["p2", "p3"]]
    assert all(group["eps"] == 1e-8 and group["lr"] == 1e-4 for group in optimizer.param_groups)


def test_torch_optimizer_regroup_rejects_existing_state():
    import torch

    parameter = torch.nn.Parameter(torch.ones(2))
    optimizer = torch.optim.AdamW([parameter])
    optimizer.state[parameter]["step"] = torch.tensor(1.0)

    try:
        regroup_torch_optimizer(optimizer, target_elements=1, parameter_names={id(parameter): "p"})
    except ValueError as exc:
        assert "before the first optimizer step" in str(exc)
    else:
        raise AssertionError("optimizer groups cannot change after state creation")


def test_fused_optimizer_group_step_matches_full_step_and_restores_lists(monkeypatch):
    """Exercise real Apex Python step with its GPU kernel replaced by CPU math."""
    import torch
    import apex.optimizers.fused_adam as apex_module
    from deepspeed.runtime.zero.stage_1_and_2 import DeepSpeedZeroOptimizer
    from groot_optimization.zero2_allgather import _optimizer_step_for_group

    def cpu_apply(_kernel, _overflow, tensors, lr, beta1, beta2, eps, step,
                  adam_w_mode, bias_correction, weight_decay):
        assert adam_w_mode == bias_correction == 1
        with torch.no_grad():
            for grad, param, mean, variance in zip(*tensors):
                mean.mul_(beta1).add_(grad, alpha=1 - beta1)
                variance.mul_(beta2).addcmul_(grad, grad, value=1 - beta2)
                denom = variance.sqrt().div_((1 - beta2 ** step) ** .5).add_(eps)
                param.mul_(1 - lr * weight_decay)
                param.addcdiv_(mean, denom, value=-lr / (1 - beta1 ** step))

    monkeypatch.setattr(apex_module, "multi_tensor_applier", cpu_apply)

    def make_optimizer():
        parameters = [torch.nn.Parameter(torch.tensor([1.0, 2.0])),
                      torch.nn.Parameter(torch.tensor([3.0, 4.0, 5.0])),
                      torch.nn.Parameter(torch.tensor([6.0]))]
        optimizer = apex_module.FusedAdam.__new__(apex_module.FusedAdam)
        torch.optim.Optimizer.__init__(optimizer, [{"params": [p]} for p in parameters],
            {"lr": .01, "betas": (.9, .99), "eps": 1e-8,
             "weight_decay": .01, "bias_correction": True})
        optimizer.param_groups_master = [{"params": [None]} for _ in parameters]
        optimizer.adam_w_mode, optimizer.capturable, optimizer.master_weights = 1, False, False
        optimizer._dummy_overflow_buf = torch.zeros(1, dtype=torch.int)
        optimizer.multi_tensor_adam = object()
        return optimizer, parameters

    reference, expected = make_optimizer()
    actual, observed = make_optimizer()
    # Mimic regrouping having invalidated Apex's parallel group list.
    actual.param_groups_master = [{"params": []}]
    stale_master = actual.param_groups_master
    original_groups = actual.param_groups

    class ZeroOptimizer:
        optimizer = actual
        torch_autocast_gradscaler = False
        zenflow = False

        def _lazy_init_hp_params_optimizer_state(self):
            pass

        def _optimizer_step(self, index):
            return DeepSpeedZeroOptimizer._optimizer_step(self, index)

    for step in range(3):
        for index, (left, right) in enumerate(zip(expected, observed)):
            left.grad = torch.full_like(left, (step + 1) * (index + 1) / 10)
            right.grad = left.grad.clone()
        reference.step()
        for index in range(len(observed)):
            _optimizer_step_for_group(ZeroOptimizer(), index)
        for left, right in zip(expected, observed):
            torch.testing.assert_close(left, right)
            torch.testing.assert_close(reference.state[left]["exp_avg"], actual.state[right]["exp_avg"])
            torch.testing.assert_close(reference.state[left]["exp_avg_sq"], actual.state[right]["exp_avg_sq"])
        assert actual.param_groups is original_groups
        assert actual.param_groups_master is stale_master
    assert [g['step'] for g in actual.param_groups] == [3, 3, 3]


def test_fused_group_adapter_restores_lists_if_step_raises(monkeypatch):
    import pytest
    import torch
    import apex.optimizers.fused_adam as apex_module
    from groot_optimization.zero2_allgather import _optimizer_step_for_group

    param = torch.nn.Parameter(torch.ones(1))
    optimizer = apex_module.FusedAdam.__new__(apex_module.FusedAdam)
    torch.optim.Optimizer.__init__(optimizer, [param], {})
    optimizer.adam_w_mode, optimizer.capturable, optimizer.master_weights = 1, False, False
    optimizer.param_groups_master = [{"params": [None]}]
    groups, masters = optimizer.param_groups, optimizer.param_groups_master

    class ZeroOptimizer:
        def __init__(self): self.optimizer = optimizer
        def _optimizer_step(self, index):
            self.optimizer.param_groups = [groups[index]]
            raise RuntimeError("update failed")

    with pytest.raises(RuntimeError, match="update failed"):
        _optimizer_step_for_group(ZeroOptimizer(), 0)
    assert optimizer.param_groups is groups
    assert optimizer.param_groups_master is masters


def test_plain_adamw_group_step_does_not_import_apex(monkeypatch):
    import builtins
    import torch
    from groot_optimization.zero2_allgather import _optimizer_step_for_group

    optimizer = torch.optim.AdamW([torch.nn.Parameter(torch.ones(1))])
    events = []
    class ZeroOptimizer:
        def __init__(self): self.optimizer = optimizer
        def _optimizer_step(self, index): events.append(index)
    original_import = builtins.__import__
    def import_without_apex(name, *args, **kwargs):
        if name.startswith('apex'):
            raise AssertionError('ordinary AdamW must not import Apex')
        return original_import(name, *args, **kwargs)
    monkeypatch.setattr(builtins, '__import__', import_without_apex)
    _optimizer_step_for_group(ZeroOptimizer(), 0)
    assert events == [0]



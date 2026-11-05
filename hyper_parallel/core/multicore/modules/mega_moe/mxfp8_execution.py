# Copyright 2026 Huawei Technologies Co., Ltd
#
# Licensed under the Apache License, Version 2.0 (the "License");
# you may not use this file except in compliance with the License.
# You may obtain a copy of the License at
#
# http://www.apache.org/licenses/LICENSE-2.0
#
# Unless required by applicable law or agreed to in writing, software
# distributed under the License is distributed on an "AS IS" BASIS,
# WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
# See the License for the specific language governing permissions and
# limitations under the License.
# ============================================================================
"""Orchestrate native MX expert graphs without retaining gathered weight views."""

from __future__ import annotations

from dataclasses import dataclass
from functools import partial
from typing import Any

import torch
import torch_npu

from hyper_parallel.core.multicore.torch import ops as multicore_ops

from .mxfp8_function import MXFP8ForwardState
from .mxfp8_diagnostics import current_mx_profile_scope, mx_profile_capture_enabled, profile_mx_launch
from .mxfp8_ops import launch_mxfp8_task_graph, prepare_mxfp8_launch, serialize_mxfp8_launch
from .mxfp8_weights import MXFP8PhysicalWeight
from .mxfp8_replica import lease_replica_weights, reduce_replica_gradients
from .route import prepare_topk_route


@dataclass(frozen=True)
class _ExecutionMetadata:
    plan: Any
    hidden_shape: tuple[int, ...]
    source_rows: int
    probs_dtype: torch.dtype


def _quantized_buffers(rows: int, columns: int, experts: int, device: Any) -> tuple[torch.Tensor, ...]:
    """Allocate both data axes and preserve grouped packed-column padding."""
    return (
        torch.empty((rows, columns), dtype=torch.float8_e4m3fn, device=device),
        torch.empty((rows, columns // 64, 2), dtype=torch.uint8, device=device),
        torch.empty((rows, columns), dtype=torch.float8_e4m3fn, device=device),
        torch.empty(((rows + 63) // 64 + experts, columns, 2), dtype=torch.uint8, device=device),
    )


def _use_row_only(spec: Any, retain_backward: bool) -> bool:
    return spec.mx_swiglu_row_only and not retain_backward


def _unpermute_mx_output(expert_output: torch.Tensor, mapping: torch.Tensor, probs: torch.Tensor,
                         routed_buffer: torch.Tensor, require_owned: bool) -> tuple[torch.Tensor, torch.Tensor]:
    """Restore tokens while keeping a no-clone checkpoint result independent of workspace reuse."""
    probabilities = probs.float().contiguous()
    output = torch_npu.npu_moe_token_unpermute(expert_output, mapping, probs=probabilities)
    if require_owned and output.untyped_storage().data_ptr() == routed_buffer.untyped_storage().data_ptr():
        raise RuntimeError("No-grad MX unpermute output must not alias shared routed storage.")
    return output, probabilities


class MXFP8Execution:
    """Own one autograd invocation's orchestration while borrowing serial resources."""

    def __init__(
        self,
        resources: Any,
        *,
        nograd_no_clone: bool = False,
        replica_route: Any = None,
        counts: torch.Tensor | None = None,
    ) -> None:
        """Bind validated invocation resources without retaining gathered weight views."""
        self.resources = resources
        self.replica_route = replica_route
        self.counts = counts
        self.nograd_no_clone = nograd_no_clone
        self._profile_scope = None

    def _launch(
        self,
        buffers: list[torch.Tensor],
        runtime: Any,
        events: torch.Tensor,
        plan: Any,
        device: Any,
        direction: str = "forward",
        *,
        swiglu_row_only: bool = False,
    ) -> None:
        if events.numel() < runtime.event_capacity * 4:
            raise ValueError("MXFP8 workspace event storage is smaller than the current graph event capacity.")
        launch_graph = (
            partial(launch_mxfp8_task_graph, vector_policy=plan.spec.mx_vector_policy)
            if plan.spec.mx_vector_policy != "legacy_odd"
            else launch_mxfp8_task_graph
        )
        if swiglu_row_only:
            launch_graph = partial(launch_graph, swiglu_row_only=True)
        if mx_profile_capture_enabled():
            scope = current_mx_profile_scope()
            if direction == "forward":
                self._profile_scope = scope
            elif scope is None:
                scope = self._profile_scope
            if scope is not None and direction == "backward":
                scope = {**scope, "phase": "backward"}
            profile_mx_launch(
                buffers, runtime, events, plan.spec, direction, prepare_mxfp8_launch, launch_graph, scope=scope
            )
            return
        diagnostic = torch.zeros(64, dtype=torch.uint8, device=device)
        if getattr(self.resources, "metadata_transfer", None) is None:
            launch = prepare_mxfp8_launch(buffers, runtime.runtime, events, plan.spec)
            launch_graph(buffers, runtime.runtime, events, diagnostic, launch)
        else:
            content = serialize_mxfp8_launch(buffers, runtime.runtime, events, plan.spec)
            self.resources.metadata_transfer.launch(
                content,
                runtime.runtime.device,
                lambda launch: launch_graph(buffers, runtime.runtime, events, diagnostic, launch),
            )

    def forward(
        self,
        hidden: torch.Tensor,
        ids: torch.Tensor,
        probs: torch.Tensor,
        weight1: MXFP8PhysicalWeight,
        weight2: MXFP8PhysicalWeight,
        retain_backward: bool,
    ) -> MXFP8ForwardState:
        """Execute the forward graph with current column weights and owned saved activations.

        Args:
            hidden: Original token-major activation tensor.
            ids: Final physical expert IDs for each selected route.
            probs: Original differentiable Router probabilities.
            weight1: Current first-projection physical weight axes.
            weight2: Current second-projection physical weight axes.
            retain_backward: Whether to retain owned activations for a later backward.
        """
        resources, workspace = self.resources, self.resources.workspace
        home_only = self.replica_route is not None and self.replica_route.home_only
        spec = resources.home_spec if home_only else resources.spec
        flat = hidden.reshape(-1, spec.hidden_size)
        route = prepare_topk_route(
            flat, ids, probs, spec, self.counts, workspace=workspace, replica_route=self.replica_route
        )
        resources.ensure_capacity(route.maximum_received_slots)
        workspace.ensure(resources.spec, hidden.dtype, hidden.device)
        plan = resources.plan_for_capacity(workspace.expert_capacity, hidden.device, home_only=home_only)
        resources.last_execution_plan = plan
        metadata = route.metadata
        capacity, device = metadata.expert_capacity, hidden.device
        x_row, x_scale, x_col, x_col_scale = _quantized_buffers(capacity, spec.hidden_size, spec.local_experts, device)
        a_row, a_scale, a_col, a_col_scale = _quantized_buffers(
            capacity, spec.intermediate_size, spec.local_experts, device
        )
        up = torch.empty((capacity, 2 * spec.intermediate_size), dtype=torch.bfloat16, device=device)
        down = torch.empty((capacity, spec.hidden_size), dtype=torch.bfloat16, device=device)
        workspace.claim()
        try:
            buffers = [
                workspace.expert_buffer,
                metadata.dispatch_target_off * spec.hidden_size,
                route.routed_tokens,
                metadata.dispatch_src_off * spec.hidden_size,
                metadata.dispatch_size * spec.hidden_size,
                weight1.col_data,
                metadata.group_list,
                up,
                a_row,
                weight2.col_data,
                metadata.group_list,
                down,
                workspace.routed_buffer,
                metadata.combine_target_off * spec.hidden_size,
                metadata.combine_src_off * spec.hidden_size,
                metadata.combine_size * spec.hidden_size,
                x_row,
                x_scale,
                x_col,
                x_col_scale,
                a_scale,
                a_col,
                a_col_scale,
                weight1.col_scale,
                weight2.col_scale,
                plan.forward.gmm,
                plan.forward.quant,
            ]
            events = workspace.prepare_event_counters(forward=True)
            with lease_replica_weights((weight1, weight2), self.replica_route, backward=False) as guests:
                buffers.extend(guests)
                self._launch(buffers, plan.forward, events, plan, device)
            expert_output = workspace.routed_buffer[: route.routed_tokens.shape[0]]
            if retain_backward or not self.nograd_no_clone:
                expert_output = expert_output.clone()
            output, probabilities = _unpermute_mx_output(
                expert_output, route.unpermute_mapping, probs, workspace.routed_buffer,
                self.nograd_no_clone and not retain_backward)
            saved = (
                (
                    x_col,
                    x_col_scale,
                    a_col,
                    a_col_scale,
                    up,
                    expert_output,
                    probabilities,
                    route.unpermute_mapping,
                    metadata.group_list,
                    metadata.dispatch_target_off,
                    metadata.dispatch_src_off,
                    metadata.dispatch_size,
                    metadata.combine_target_off,
                    metadata.combine_src_off,
                    metadata.combine_size,
                )
                if retain_backward
                else ()
            )
            return MXFP8ForwardState(
                output.reshape_as(hidden),
                saved,
                _ExecutionMetadata(plan, tuple(hidden.shape), route.routed_tokens.shape[0], probs.dtype),
                workspace,
            )
        finally:
            workspace.release()

    def backward(
        self,
        gradient: torch.Tensor,
        saved: tuple[torch.Tensor, ...],
        metadata: _ExecutionMetadata,
        weight1: MXFP8PhysicalWeight,
        weight2: MXFP8PhysicalWeight,
    ) -> tuple[torch.Tensor, ...]:
        """Resolve current dual-axis weights and return logical owner gradients.

        Args:
            gradient: Gradient of the owned token-major output.
            saved: Owned forward activations and exact route metadata.
            metadata: Invocation plan, shape, probability dtype and source-row count.
            weight1: Current first-projection physical weight axes.
            weight2: Current second-projection physical weight axes.
        """
        workspace, plan = self.resources.workspace, metadata.plan
        spec, device = plan.spec, gradient.device
        (
            x_col,
            x_col_scale,
            a_col,
            a_col_scale,
            up,
            expert_output,
            probs,
            mapping,
            group_list,
            dispatch_target,
            dispatch_source,
            dispatch_size,
            combine_target,
            combine_source,
            combine_size,
        ) = saved
        capacity = x_col.shape[0]
        dy_row, dy_scale, dy_col, dy_col_scale = _quantized_buffers(
            capacity, spec.hidden_size, spec.local_experts, device
        )
        du_row, du_scale, du_col, du_col_scale = _quantized_buffers(
            capacity, 2 * spec.intermediate_size, spec.local_experts, device
        )
        source = torch.empty((metadata.source_rows, spec.hidden_size), dtype=torch.bfloat16, device=device)
        grad_probs = torch.empty_like(probs)
        da = torch.empty((capacity, spec.intermediate_size), dtype=torch.bfloat16, device=device)
        dx = torch.empty((capacity, spec.hidden_size), dtype=torch.bfloat16, device=device)
        # TN stores complete matrices; its zero-K path explicitly clears empty experts.
        dw1 = torch.empty((spec.local_experts, *weight1.logical_shape[1:]), dtype=torch.float32, device=device)
        dw2 = torch.empty((spec.local_experts, *weight2.logical_shape[1:]), dtype=torch.float32, device=device)
        workspace.claim()
        try:
            multicore_ops.mega_moe_unpermute_grad_out(
                expert_output,
                gradient.reshape(-1, spec.hidden_size).contiguous(),
                mapping,
                probs,
                source,
                grad_probs,
            )
            buffers = [
                workspace.expert_buffer,
                dispatch_target * spec.hidden_size,
                source,
                dispatch_source * spec.hidden_size,
                dispatch_size * spec.hidden_size,
                a_col,
                dw2,
                weight2.row_data,
                da,
                up,
                du_row,
                weight1.row_data,
                dx,
                workspace.routed_buffer,
                combine_target * spec.hidden_size,
                combine_source * spec.hidden_size,
                combine_size * spec.hidden_size,
                x_col,
                dw1,
                group_list,
                dy_row,
                dy_scale,
                dy_col,
                dy_col_scale,
                a_col_scale,
                weight2.row_scale,
                du_scale,
                du_col,
                du_col_scale,
                weight1.row_scale,
                x_col_scale,
                plan.backward.gmm,
                plan.backward.quant,
            ]
            events = workspace.prepare_event_counters(forward=False)
            with lease_replica_weights((weight1, weight2), self.replica_route, backward=True) as guests:
                buffers.extend(guests)
                self._launch(buffers, plan.backward, events, plan, device, direction="backward")
            grad_hidden = multicore_ops.moe_token_permute_grad(
                workspace.routed_buffer[: metadata.source_rows],
                mapping,
                gradient.numel() // spec.hidden_size,
                spec.top_k,
            )
            dw1, dw2 = reduce_replica_gradients((dw1, dw2), self.replica_route)
            return grad_hidden.reshape(metadata.hidden_shape), grad_probs.to(metadata.probs_dtype), dw1, dw2
        finally:
            workspace.release()

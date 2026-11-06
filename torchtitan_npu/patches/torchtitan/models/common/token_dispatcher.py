# Pending upstream PR: https://github.com/pytorch/torchtitan/pull/5543

# Copyright (c) Meta Platforms, Inc. and affiliates.
# All rights reserved.
#
# This source code is licensed under the BSD-style license found in the
# LICENSE file in the root directory of this source tree.

"""Adapt PR 5543 score transport for pre-W2 router-score absorption.

The PR's rematerialization changes are not included.

The TorchTitan revision pinned by ``requirements.txt`` applies scores after
combine. This patch adds the opt-in score transport needed by standard EP1/EP2
dispatch while keeping the default path numerically identical. DeepEP only
exposes the same ``absorb_router_scores`` configuration knob here; pre-W2
absorption is implemented by the NPU dispatcher override. HybridEP,
MinimalAsyncEP, and TorchAO keep their pinned behavior and are not patched here.
The dispatcher contract follows the upstream design in
https://github.com/pytorch/torchtitan/pull/5543.
"""

# pylint: disable=huawei-invalid-name

from dataclasses import dataclass

import spmd_types as spmd
import torch
import torch_remat as remat
from torchtitan.distributed.spmd_types import maybe_set_sparse_mesh, spmd_mesh_group
from torchtitan.models.common.token_dispatcher import (
    AllToAllDispatchMetadata as TorchTitanAllToAllDispatchMetadata,
)
from torchtitan.models.common.token_dispatcher import (
    AllToAllTokenDispatcher as TorchTitanAllToAllTokenDispatcher,
)
from torchtitan.models.common.token_dispatcher import (
    DeepEPTokenDispatcher as TorchTitanDeepEPTokenDispatcher,
)
from torchtitan.models.common.token_dispatcher import (
    LocalDispatchMetadata as TorchTitanLocalDispatchMetadata,
)
from torchtitan.models.common.token_dispatcher import (
    LocalTokenDispatcher as TorchTitanLocalTokenDispatcher,
)
from torchtitan.ops.scatter_add import deterministic_scatter_add


@dataclass(frozen=True, kw_only=True)
class LocalDispatchMetadata(TorchTitanLocalDispatchMetadata):
    """Local dispatch metadata with optional pre-W2 router scores."""

    routed_scores_R: torch.Tensor | None = None  # noqa: N815


@dataclass(frozen=True, kw_only=True)
class AllToAllDispatchMetadata(TorchTitanAllToAllDispatchMetadata):
    """All-to-all metadata with optional pre-W2 router scores."""

    routed_scores_R: torch.Tensor | None = None  # noqa: N815


class LocalTokenDispatcher(TorchTitanLocalTokenDispatcher):
    """Local dispatcher with optional pre-W2 router-score absorption."""

    @dataclass(kw_only=True, slots=True)
    class Config(TorchTitanLocalTokenDispatcher.Config):
        # Patch override: retain router scores for pre-W2 absorption.
        absorb_router_scores: bool = False

    def __init__(self, config: Config):
        super().__init__(config)
        self.absorb_router_scores = config.absorb_router_scores

    def dispatch(
        self,
        x_TD: torch.Tensor,
        topk_scores_TK: torch.Tensor,
        topk_expert_ids_TK: torch.Tensor,
        num_local_tokens_per_expert_E: torch.Tensor,
    ):
        (
            routed_input_rd,
            token_indices_experts_sorted_N,
            topk_scores_experts_sorted_N,
        ) = self._local_reorder(x_TD, topk_scores_TK, topk_expert_ids_TK)
        # Patch override: carry the expert-sorted scores in dispatch metadata
        # so grouped experts can apply them before the down projection.
        routed_scores_R = topk_scores_experts_sorted_N if self.absorb_router_scores else None
        # Patch override: extend the upstream metadata with routed scores.
        metadata = LocalDispatchMetadata(
            token_indices_experts_sorted_N=token_indices_experts_sorted_N,
            topk_scores_experts_sorted_N=topk_scores_experts_sorted_N,
            routed_scores_R=routed_scores_R,
        )
        return routed_input_rd, num_local_tokens_per_expert_E, metadata

    # Preserve upstream dimension-annotated keyword parameters.
    def combine(  # pylint: disable=invalid-name
        self,
        routed_output_RD: torch.Tensor,
        metadata: TorchTitanLocalDispatchMetadata,
        x_TD: torch.Tensor,
    ) -> torch.Tensor:
        out_TD = torch.zeros_like(x_TD)
        # Patch override: the config is the single source of truth; skip the
        # multiply when grouped experts applied scores before down projection.
        if not self.absorb_router_scores:
            routed_output_RD = (
                routed_output_RD.to(torch.float32) * metadata.topk_scores_experts_sorted_N.reshape(-1, 1)
            ).to(routed_output_RD.dtype)
        dim = x_TD.shape[-1]
        return deterministic_scatter_add(
            out_TD,
            metadata.token_indices_experts_sorted_N.reshape(-1, 1).expand(-1, dim),
            routed_output_RD,
        )


class AllToAllTokenDispatcher(TorchTitanAllToAllTokenDispatcher):
    """Standard EP dispatcher with optional pre-W2 router-score absorption."""

    def _sync_token_count_exchange(  # pyrefly: ignore [bad-override]
        self,
        num_local_tokens_per_expert_E: torch.Tensor,
        num_global_tokens_per_local_expert_EP_e: torch.Tensor,
        ep_size: int,
    ) -> tuple[torch.Tensor, list[int], list[int]]:
        # Patch override: keep exactly two blocking _to_copy CPU copies
        # in this method. Upstream's graph_trainer ep_overlap pass tags the
        # ops launched here (annotate_moe_ep_regions wraps this override)
        # and structurally validates "exactly two token-count sync CPU
        # copies" per MoE chunk -- it schedules the region around the pair
        # and rewrites the first copy to non_blocking while the last one
        # stays blocking. Merging both copies into one stacked D2H (PR
        # #1036) left a single tagged copy and crashed GraphTrainer at
        # graph build time. Each copy also blocks on its own: upstream's
        # original async input_splits copy races under inductor scheduling
        # (reads hoisted above the blocking output_splits copy read
        # uninitialized memory -- "Split sizes doesn't match total dim 0
        # size" at the variable-size data all-to-all).
        num_global_tokens_per_local_expert_EP_e = torch.ops._c10d_functional.wait_tensor(
            num_global_tokens_per_local_expert_EP_e
        )
        num_global_tokens_per_local_expert_E = num_global_tokens_per_local_expert_EP_e.reshape(-1)
        input_splits = (
            num_local_tokens_per_expert_E.view(ep_size, -1).sum(dim=1).to(torch.device("cpu"), non_blocking=False)
        )
        output_splits = (
            num_global_tokens_per_local_expert_E.view(ep_size, -1)
            .sum(dim=1)
            .to(torch.device("cpu"), non_blocking=False)
        )
        input_splits_list = input_splits.tolist()
        output_splits_list = output_splits.tolist()

        return (
            num_global_tokens_per_local_expert_E,
            input_splits_list,
            output_splits_list,
        )

    @dataclass(kw_only=True, slots=True)
    class Config(TorchTitanAllToAllTokenDispatcher.Config):
        # Patch override: retain router scores for pre-W2 absorption.
        absorb_router_scores: bool = False

    def __init__(self, config: Config):
        super().__init__(config)
        self.absorb_router_scores = config.absorb_router_scores

    def dispatch(
        self,
        x_TD: torch.Tensor,
        topk_scores_TK: torch.Tensor,
        topk_expert_ids_TK: torch.Tensor,
        num_local_tokens_per_expert_E: torch.Tensor,
    ):
        if self.ep_mesh is None:
            return LocalTokenDispatcher.dispatch(
                self,  # pyrefly: ignore [bad-argument-type]
                x_TD,
                topk_scores_TK,
                topk_expert_ids_TK,
                num_local_tokens_per_expert_E,
            )

        ep_size = self.ep_mesh.size()
        (
            routed_input_ND,
            token_indices_experts_sorted_N,
            topk_scores_experts_sorted_N,
        ) = self._local_reorder(x_TD, topk_scores_TK, topk_expert_ids_TK)
        # Patch override: keep scores aligned with the rank-major token stream
        # so they can follow the same EP all-to-all as routed activations.
        routed_scores_N = topk_scores_experts_sorted_N if self.absorb_router_scores else None

        if spmd.is_type_checking():
            for axis in ("dp", "cp", "tp"):
                spmd.mutate_type(num_local_tokens_per_expert_E, axis, src=spmd.P, dst=spmd.V)

        with maybe_set_sparse_mesh():
            pg = spmd_mesh_group("ep")
            assert pg is not None
            if spmd.is_type_checking():
                num_local_tokens_per_expert_E = spmd.reinterpret_mesh(
                    num_local_tokens_per_expert_E, spmd.current_mesh()
                )
                routed_input_ND = spmd.reinterpret_mesh(routed_input_ND, spmd.current_mesh())
                if routed_scores_N is not None:
                    routed_scores_N = spmd.reinterpret_mesh(routed_scores_N, spmd.current_mesh())

            with torch.no_grad():
                num_global_tokens_per_local_expert_EP_e = self._token_count_exchange(
                    num_local_tokens_per_expert_E, pg, ep_size
                )
                (
                    num_global_tokens_per_local_expert_E,
                    input_splits_list,
                    output_splits_list,
                ) = self._sync_token_count_exchange(
                    num_local_tokens_per_expert_E,
                    num_global_tokens_per_local_expert_EP_e,
                    ep_size,
                )

            routed_input_rd = remat.region(
                self._dispatch_token_exchange,
                self.remat_region_name("ep_communication.dispatch"),
                recompute=self.remat_should_recompute("ep_communication"),
            )(routed_input_ND, pg, output_splits_list, input_splits_list)
            remat.recompute_needs_tensor(routed_input_rd)
            # Patch override: transport router scores through EP in their
            # original dtype, alongside the routed activations.
            routed_scores_rank_major_R = (
                self._dispatch_token_exchange(
                    routed_scores_N.reshape(-1, 1), pg, output_splits_list, input_splits_list
                ).reshape(-1)
                if routed_scores_N is not None
                else None
            )
            (
                input_shape,
                routed_input_rd,
                permuted_indices,
                num_global_tokens_per_local_expert_e,
                routed_scores_R,
            ) = self._permute(
                routed_input_rd,
                num_global_tokens_per_local_expert_E,
                routed_scores_rank_major_R,
            )

        metadata = AllToAllDispatchMetadata(
            token_indices_experts_sorted_N=token_indices_experts_sorted_N,
            topk_scores_experts_sorted_N=topk_scores_experts_sorted_N,
            input_shape=input_shape,
            permuted_indices=permuted_indices,
            input_splits=input_splits_list,
            output_splits=output_splits_list,
            # Patch override: expose the EP-aligned scores to grouped experts.
            routed_scores_R=routed_scores_R,
        )
        return routed_input_rd, num_global_tokens_per_local_expert_e, metadata

    def _permute(  # pyrefly: ignore[bad-override]
        self,
        routed_input_RD: torch.Tensor,
        num_global_tokens_per_local_expert_E: torch.Tensor,
        routed_scores_rank_major_R: torch.Tensor | None = None,
    ):
        """Reorder rank-major tokens (and optional scores) to expert-major."""
        (
            input_shape,
            routed_input_RD,
            permuted_indices,
            num_global_tokens_per_local_expert_e,
        ) = super()._permute(
            routed_input_RD,
            num_global_tokens_per_local_expert_E,
        )
        # Patch override: scores must follow the same rank-major -> expert-major
        # index mapping as routed_input_RD.
        routed_scores_R = (
            routed_scores_rank_major_R[permuted_indices] if routed_scores_rank_major_R is not None else None
        )
        return (
            input_shape,
            routed_input_RD,
            permuted_indices,
            num_global_tokens_per_local_expert_e,
            routed_scores_R,
        )

    # Preserve upstream dimension-annotated keyword parameters.
    def combine(  # pylint: disable=invalid-name
        self,
        routed_output_RD: torch.Tensor,
        metadata: TorchTitanAllToAllDispatchMetadata | TorchTitanLocalDispatchMetadata,
        x_TD: torch.Tensor,
    ) -> torch.Tensor:
        if self.ep_mesh is None:
            assert isinstance(metadata, TorchTitanLocalDispatchMetadata)
            return LocalTokenDispatcher.combine(
                self,  # pyrefly: ignore [bad-argument-type]
                routed_output_RD,
                metadata,
                x_TD,
            )

        assert isinstance(metadata, TorchTitanAllToAllDispatchMetadata)
        with maybe_set_sparse_mesh():
            pg = spmd_mesh_group("ep")
            assert pg is not None
            routed_output_RD = self._unpermute(routed_output_RD, metadata.input_shape, metadata.permuted_indices)
            routed_output_RD = self._combine_token_exchange(
                routed_output_RD, pg, metadata.input_splits, metadata.output_splits
            )

        if spmd.is_type_checking():
            routed_output_RD = spmd.reinterpret_mesh(routed_output_RD, spmd.current_mesh())

        out_TD = torch.zeros_like(x_TD)
        token_indices_experts_sorted_n = metadata.token_indices_experts_sorted_N
        # Patch override: use the dispatcher config instead of a per-call flag;
        # grouped experts may have absorbed scores before the down projection.
        if not self.absorb_router_scores:
            routed_output_RD = (
                routed_output_RD.to(torch.float32) * metadata.topk_scores_experts_sorted_N.reshape(-1, 1)
            ).to(routed_output_RD.dtype)

        assert isinstance(token_indices_experts_sorted_n, torch.Tensor)
        return deterministic_scatter_add(
            out_TD,
            token_indices_experts_sorted_n.reshape(-1, 1).expand(-1, out_TD.shape[-1]),
            routed_output_RD,
        )


class DeepEPTokenDispatcher(TorchTitanDeepEPTokenDispatcher):
    """Expose the absorption setting for backend-specific DeepEP dispatchers."""

    @dataclass(kw_only=True, slots=True)
    class Config(TorchTitanDeepEPTokenDispatcher.Config):
        absorb_router_scores: bool = False

    def __init__(self, config: Config):
        super().__init__(config)
        self.absorb_router_scores = config.absorb_router_scores


def apply() -> None:
    import torchtitan.models.common.config_utils
    import torchtitan.models.common.token_dispatcher as token_dispatcher_module

    token_dispatcher_module.LocalTokenDispatcher = LocalTokenDispatcher  # pyrefly: ignore [bad-assignment]
    token_dispatcher_module.AllToAllTokenDispatcher = AllToAllTokenDispatcher  # pyrefly: ignore [bad-assignment]
    token_dispatcher_module.DeepEPTokenDispatcher = DeepEPTokenDispatcher  # pyrefly: ignore [bad-assignment]

    # Patch override: DeepSeek-V4's ``_make_moe_config()`` calls
    # ``config_utils.make_routed_experts_config()``, whose module-level
    # ``from`` imports cached the upstream dispatcher classes. Refresh those
    # bindings so its factory builds configs with the patched dispatcher
    # contracts.
    torchtitan.models.common.config_utils.LocalTokenDispatcher = (  # pyrefly: ignore [bad-assignment]
        LocalTokenDispatcher
    )
    torchtitan.models.common.config_utils.AllToAllTokenDispatcher = (  # pyrefly: ignore [bad-assignment]
        AllToAllTokenDispatcher
    )
    torchtitan.models.common.config_utils.DeepEPTokenDispatcher = (  # pyrefly: ignore [bad-assignment]
        DeepEPTokenDispatcher
    )


apply()

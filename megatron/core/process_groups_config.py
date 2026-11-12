# Copyright (c) 2026 NVIDIA CORPORATION & AFFILIATES. All rights reserved.

"""Dataclasses for organizing model parallelism and gradient communication process groups."""

from dataclasses import dataclass, field, fields
from datetime import timedelta
from functools import partial
from typing import Any, Dict, List, Optional, Sequence, Tuple, Union

import torch

from megatron.core import parallel_state

# Domains every model has: dense parameters are replicated over dp_cp and expert parameters over
# expt_dp. Any other domain is an extra one, whose replica group the model registers in
# ProcessGroupCollection.parameter_replica_groups.
IMPLICIT_PARAMETER_DOMAINS = ('dense', 'expert')


def get_parameter_parallel_domain(parameter: Union[torch.Tensor, Dict[str, Any]]) -> str:
    """Return the replica domain of a parameter or of an optimizer param group.

    A domain names the group over which copies of a parameter are kept in sync: ``'dense'``
    (dp_cp), ``'expert'`` (expt_dp), or an extra domain whose group is registered in
    ``ProcessGroupCollection.parameter_replica_groups``. Parameters and optimizer metadata
    store only the name; the process groups stay in the collection.

    A parameter's ``parallel_domain`` attribute wins; otherwise ``allreduce=False`` marks an
    expert parameter. A param group carries ``parallel_domain`` only for an extra domain and is
    otherwise dense or expert according to its ``is_expert_parallel`` flag.

    Args:
        parameter: A parameter, or a param-group dict built by the optimizer factory.

    Returns:
        str: The domain name.
    """
    if isinstance(parameter, dict):
        return parameter.get('parallel_domain') or (
            'expert' if parameter.get('is_expert_parallel', False) else 'dense'
        )
    return getattr(parameter, 'parallel_domain', None) or (
        'dense' if getattr(parameter, 'allreduce', True) else 'expert'
    )


def replica_group_shard(
    parent_ranks: Sequence[int], replica_ranks: Sequence[int]
) -> Tuple[int, int]:
    """Return ``(o, n)`` for a replica group that is the strided slice ``parent[o::n]``.

    ``create_row_parallel_groups`` builds replica groups this way: one per row shard ``o`` of the
    ``n`` shards of the parent (a pipeline stage's dp_cp group). Data-parallel reduction and the
    naming of a domain's optimizer both rely on it.

    Raises:
        ValueError: If the replica group is not such a slice of the parent.
    """
    parent_ranks, replica_ranks = list(parent_ranks), list(replica_ranks)
    num_shards = len(parent_ranks) // len(replica_ranks) if replica_ranks else 0
    shard = (
        parent_ranks.index(replica_ranks[0])
        if replica_ranks and replica_ranks[0] in parent_ranks
        else -1
    )
    if not 0 <= shard < num_shards or parent_ranks[shard::num_shards] != replica_ranks:
        raise ValueError(
            f"Replica group {replica_ranks} is not a strided slice parent[o::n] of {parent_ranks}, "
            "as create_row_parallel_groups builds it."
        )
    return shard, num_shards


def create_row_parallel_groups(
    parent_group: torch.distributed.ProcessGroup,
    shard_size: int,
    *,
    world_group: Optional[torch.distributed.ProcessGroup],
    name: str,
    timeout: Optional[timedelta] = None,
) -> Tuple[torch.distributed.ProcessGroup, torch.distributed.ProcessGroup, List[List[int]]]:
    """Split parent groups into row-shard groups and the replica groups across them.

    Each parent group (for example the dp_cp group of one pipeline stage) is read as a
    [replica, row shard] mesh in its own rank order: with ``k = shard_size``, shard ``s`` holds
    ``parent[s * k : (s + 1) * k]`` and replica ``o`` holds ``parent[o::k]``. A table whose
    rows are sharded over a shard group is replicated over its replica group.

    This is a collective over ``world_group``, which must span every rank: all ranks call it
    once, at the same point. The ranks exchange their configuration before validating it, so a
    bad one raises on every rank instead of leaving the others waiting. Every rank then creates
    every group in the same order, as ``torch.distributed.new_group`` requires. The groups go
    through ``parallel_state.create_group``, which registers them for timeout updates;
    ``destroy_model_parallel`` does not release them, so callers drop their own references.

    Communicators are created at a group's first collective, so an unused group costs nothing.
    In case a launcher creates them eagerly, single-rank NCCL groups are limited to one CTA.

    Args:
        parent_group (ProcessGroup): This rank's parent group. The parents of all ranks must
            partition the world.
        shard_size (int): Ranks per row shard; must divide the size of every parent. When it
            equals a parent's size, that parent group itself is the shard group; when it is 1,
            the parent group itself is the replica group. Neither then gets a second
            communicator over the same ranks.
        world_group (ProcessGroup): Group spanning all ranks, used to exchange the parents
            (None for the default group).
        name (str): Prefix of the group descriptions ``{name}_SHARD`` and ``{name}_REPLICA``.
        timeout (timedelta, optional): Timeout of the new groups; the backend default if None.

    Returns:
        Tuple of this rank's shard group, this rank's replica group, and the global ranks of
        every shard group of every parent, in creation order.
    """
    world_size = torch.distributed.get_world_size()
    if torch.distributed.get_world_size(world_group) != world_size:
        raise ValueError(f"{name}: row-parallel groups must be created by all {world_size} ranks")
    parent_ranks = tuple(torch.distributed.get_process_group_ranks(parent_group))
    backend = torch.distributed.get_backend(parent_group)
    descriptions = [None] * world_size
    torch.distributed.all_gather_object(
        descriptions, (parent_ranks, shard_size, backend, name), group=world_group
    )

    # Validate only after the exchange: a bad local configuration then raises on every rank
    # instead of leaving its peers waiting in the group creation below.
    if any(description[1:] != descriptions[0][1:] for description in descriptions):
        raise ValueError(
            f"{name}: shard size, backend and name must agree on all ranks, got "
            f"{sorted({str(description[1:]) for description in descriptions})}"
        )
    parents = sorted({description[0] for description in descriptions})
    if (
        type(shard_size) is not int
        or shard_size <= 0
        or any(len(parent) % shard_size for parent in parents)
    ):
        raise ValueError(
            f"{name}: shard size {shard_size!r} must be a positive divisor of every parent "
            f"group size, got sizes {sorted({len(parent) for parent in parents})}"
        )
    if sorted(rank for parent in parents for rank in parent) != list(range(world_size)):
        raise ValueError(f"{name}: parent groups must partition all {world_size} ranks")

    single_rank_pg_options = None
    if backend == torch.distributed.Backend.NCCL:
        single_rank_pg_options = torch.distributed.ProcessGroupNCCL.Options()
        single_rank_pg_options.config.max_ctas = 1
        single_rank_pg_options.config.min_ctas = 1

    rank = torch.distributed.get_rank()
    shard_group = replica_group = None
    shard_ranks = []
    for parent in parents:
        for start in range(0, len(parent), shard_size):
            ranks = list(parent[start : start + shard_size])
            shard_ranks.append(ranks)
            if shard_size == len(parent):
                # The only shard spans the parent: reuse its group (and communicator).
                group = parent_group
            else:
                group = parallel_state.create_group(
                    ranks,
                    timeout=timeout,
                    backend=backend,
                    pg_options=single_rank_pg_options if len(ranks) == 1 else None,
                    group_desc=f"{name}_SHARD",
                )
            if rank in ranks:
                shard_group = group
        for offset in range(shard_size):
            ranks = list(parent[offset::shard_size])
            if shard_size == 1:
                # The only replica spans the parent: reuse its group (and communicator).
                group = parent_group
            else:
                group = parallel_state.create_group(
                    ranks,
                    timeout=timeout,
                    backend=backend,
                    pg_options=single_rank_pg_options if len(ranks) == 1 else None,
                    group_desc=f"{name}_REPLICA",
                )
            if rank in ranks:
                replica_group = group
    assert shard_group is not None and replica_group is not None
    return shard_group, replica_group, shard_ranks


class ProcessGroupHelperMeta(type):
    """Metaclass to protect virtual_pipeline_model_parallel_size from direct assignment."""

    def __setattr__(cls, name, value):
        if name == 'virtual_pipeline_model_parallel_size':
            raise AttributeError(
                f"Cannot set '{name}' directly. Use set_virtual_pipeline_model_parallel_size() "
                f"method instead."
            )
        super().__setattr__(name, value)


@dataclass
class ProcessGroupCollection:
    """Unified process group collection for transformer model parallelism, gradient communication,
     and finalization.

    Fields use init=False and must be set after instance creation.

    Args:
        # Model Parallelism Groups
        tp: Tensor parallel process group
        pp: Pipeline parallel process group
        mp: Model parallel group (tensor + pipeline)
        embd: Embedding process group
        pos_embd: Position embedding process group
        cp: Context parallel process group
        dynamic_cp: Runtime CP groups keyed by CP size; the full DPxCP domain and
            the singleton CP-off group are included when initialized
        dynamic_tp_cp: TP x runtime-CP groups keyed by CP size (not TP x CP size)
        tp_cp: Tensor and context parallel group
        hcp: Hierarchical context parallel groups
        ep: Expert model parallel group
        expt_tp: Expert tensor parallel group
        tp_ep: Tensor and expert parallel group
        tp_ep_pp: Tensor, expert, and pipeline parallel group
        tp_ep_pp_with_egtp_remat: tp_ep_pp merged across EGTP peers (dense ``mp`` analog);
            identical to ``tp_ep_pp`` when EGTP_remat_size=1

        # Data Parallelism Groups
        dp: Data parallel process group
        dp_gtp_remat: Independent sequences, excluding all context partitions
        dp_cp: Copies of the same dense weight shard, excluding its GTP group
        dp_cp_gtp_remat: Full data-distribution group, dp_cp x gtp_remat;
            identical to dp_cp when GTP_remat_size=1
        expt_dp: Expert data parallel group
        expt_dp_gtp_remat: Full expert data-distribution group, expt_dp x egtp_remat;
            identical to expt_dp when EGTP_remat_size=1
        intra_dp_cp: Intra partial data parallel group
        intra_expt_dp: Intra partial expert data parallel group
        inter_dist_opt: Inter distributed optimizer instance group

        # Parameter Replica Domains
        engram: Row-shard group of the sharded Engram tables, a slice of dp_cp
        engram_dp: Replica group of those row shards
        parameter_replica_groups: Replica group of each extra parameter domain, keyed by
            domain name (see get_parameter_parallel_domain); 'dense' and 'expert' are implicit

    Example:
        # Create instance and set needed process groups
        pgs = ProcessGroupCollection()
        pgs.tp = tp_group
        pgs.pp = pp_group
        pgs.dp = dp_group

        # Pass to model components
        model = TransformerModel(..., pg_collection=pgs)
        ddp_model = DistributedDataParallel(..., pg_collection=pgs)
        finalize_model_grads(..., pg_collection=pgs)
    """

    # Model Parallelism Process Groups
    # _TENSOR_MODEL_PARALLEL_GROUP
    tp: torch.distributed.ProcessGroup = field(init=False)

    # _PIPELINE_MODEL_PARALLEL_GROUP
    pp: torch.distributed.ProcessGroup = field(init=False)

    # _MODEL_PARALLEL_GROUP
    mp: torch.distributed.ProcessGroup = field(init=False)

    # _EMBEDDING_GROUP
    embd: torch.distributed.ProcessGroup = field(init=False)

    # _POSITION_EMBEDDING_GROUP
    pos_embd: torch.distributed.ProcessGroup = field(init=False)

    # _CONTEXT_PARALLEL_GROUP
    cp: torch.distributed.ProcessGroup = field(init=False)

    # Runtime groups are selected per microbatch without changing the static CP group.
    dynamic_cp: Dict[int, torch.distributed.ProcessGroup] = field(init=False)

    # The map key is the CP size; each group's size is TP size times that key.
    dynamic_tp_cp: Dict[int, torch.distributed.ProcessGroup] = field(init=False)

    # _TENSOR_AND_CONTEXT_PARALLEL_GROUP
    tp_cp: torch.distributed.ProcessGroup = field(init=False)

    # _HIERARCHICAL_CONTEXT_PARALLEL_GROUPS
    hcp: List[torch.distributed.ProcessGroup] = field(init=False)

    # Expert Parallelism Process Groups
    # _EXPERT_MODEL_PARALLEL_GROUP
    ep: torch.distributed.ProcessGroup = field(init=False)

    # _EXPERT_TENSOR_PARALLEL_GROUP
    expt_tp: torch.distributed.ProcessGroup = field(init=False)

    # _EXPERT_TENSOR_AND_MODEL_PARALLEL_GROUP
    tp_ep: torch.distributed.ProcessGroup = field(init=False)

    # _EXPERT_TENSOR_MODEL_PIPELINE_PARALLEL_GROUP
    tp_ep_pp: torch.distributed.ProcessGroup = field(init=False)

    # _EXPERT_TENSOR_MODEL_PIPELINE_PARALLEL_GROUP_WITH_EGTP — expert "model parallel" group
    # merged across EGTP peers (analog of dense ``mp`` under GTP). Identical to ``tp_ep_pp``
    # when EGTP_remat_size=1.
    tp_ep_pp_with_egtp_remat: torch.distributed.ProcessGroup = field(init=False)

    # _TENSOR_AND_DATA_PARALLEL_GROUP_WITH_CP (spans gtp_remat, like dp)
    tp_dp_cp: torch.distributed.ProcessGroup = field(init=False)

    # Data Parallelism Process Groups
    # _DATA_PARALLEL_GROUP
    dp: torch.distributed.ProcessGroup = field(init=False)

    # _DATA_PARALLEL_GROUP_WITH_GTP_REMAT: independent sample owners. When sequences
    # are partitioned within GTP_remat groups, only the remaining GTP_remat batch
    # shards x DP distribute samples; all context partitions are excluded.
    # Dataloaders shard samples and index their per-rank state by this group.
    dp_gtp_remat: torch.distributed.ProcessGroup = field(init=False)

    # _DATA_PARALLEL_GROUP_WITH_CP: dense weight replicas. When sequences are
    # partitioned within GTP_remat groups, this includes only the CP extent
    # outside the weight-sharding group.
    dp_cp: torch.distributed.ProcessGroup = field(init=False)

    # _DATA_PARALLEL_GROUP_WITH_CP_WITH_GTP_REMAT — the full data-distribution group, DP x CP x
    # gtp_remat. Used where data is split/aggregated across every rank that holds a distinct
    # micro-batch (batch split, num_microbatches, loss/metric reductions, non-gtp param broadcast).
    # Identical to ``dp_cp`` when gtp_remat_size=1.
    dp_cp_gtp_remat: torch.distributed.ProcessGroup = field(init=False)

    # Separate dp_cp communicator for param all-gather (AG/RS overlap)
    dp_cp_ag: torch.distributed.ProcessGroup = field(init=False)

    # _GTP_WEIGHT_REMAT_GROUP
    gtp_remat: torch.distributed.ProcessGroup = field(init=False)

    # _EXPERT_GTP_WEIGHT_REMAT_GROUP
    expt_gtp_remat: torch.distributed.ProcessGroup = field(init=False)

    # MoE layers need expt_dp group for sharded state dict
    # we need this workaround until distributed checkpoint is refactored
    # to have sharded_state_dict can take the PG and pass it down
    # TODO (Hepteract): remove this once distributed checkpoint is refactored
    # _EXPERT_DATA_PARALLEL_GROUP
    expt_dp: torch.distributed.ProcessGroup = field(init=False)

    # _EXPERT_DATA_PARALLEL_GROUP_WITH_EGTP — full expert data-distribution group, expt_dp x
    # egtp_remat. Used for non-egtp expert param broadcast / sharded state dict over the full
    # axis. Identical to ``expt_dp`` when egtp_remat_size=1.
    expt_dp_gtp_remat: torch.distributed.ProcessGroup = field(init=False)

    # _EXPERT_DATA_PARALLEL_GROUP_AG
    expt_dp_ag: torch.distributed.ProcessGroup = field(init=False)

    # _INTRA_PARTIAL_DATA_PARALLEL_GROUP_WITH_CP
    intra_dp_cp: torch.distributed.ProcessGroup = field(init=False)

    # _INTRA_EXPERT_DATA_PARALLEL_GROUP
    intra_expt_dp: torch.distributed.ProcessGroup = field(init=False)

    # _INTER_PARTIAL_EXPERT_DATA_PARALLEL_GROUP
    inter_dist_opt: torch.distributed.ProcessGroup = field(init=False)

    # _INTRA_DISTRIBUTED_OPTIMIZER_INSTANCE_GROUP
    intra_dist_opt: torch.distributed.ProcessGroup = field(init=False)

    # Row-shard and replica groups of the sharded Engram tables, created by the model builder
    # (create_row_parallel_groups over dp_cp), never by MPU.
    engram: torch.distributed.ProcessGroup = field(init=False)
    engram_dp: torch.distributed.ProcessGroup = field(init=False)

    # Replica group of each extra parameter domain, keyed by domain name. 'dense' and 'expert'
    # are implicit (dp_cp and expt_dp); see get_parameter_replica_group.
    parameter_replica_groups: Dict[str, torch.distributed.ProcessGroup] = field(init=False)

    def __init__(self, **kwargs):
        for key in kwargs:
            if key in [field.name for field in fields(self)]:
                setattr(self, key, kwargs[key])
            else:
                raise ValueError(f"Unknown attribute: {key}")

    def __getattr__(self, name: str):
        # Return None for any declared field that was not set during partial construction
        # (e.g. when use_mpu_process_groups is called with a subset of required_pgs).
        if name in {f.name for f in fields(self.__class__)}:
            return None
        raise AttributeError(f"'ProcessGroupCollection' object has no attribute '{name}'")

    def get_parameter_replica_group(
        self, domain: str, partial: bool = False
    ) -> torch.distributed.ProcessGroup:
        """Return the group that keeps the copies of a parameter domain in sync.

        Args:
            domain (str): Domain name, as returned by get_parameter_parallel_domain.
            partial (bool): For 'dense' and 'expert', return the group within one distributed
                optimizer instance (intra_dp_cp, intra_expt_dp) when it is set. Extra domains
                support a single instance only, so they ignore it.

        Returns:
            ProcessGroup: The replica group of the domain.
        """
        if domain == 'dense':
            return self.intra_dp_cp if partial and self.intra_dp_cp is not None else self.dp_cp
        if domain == 'expert':
            return (
                self.intra_expt_dp if partial and self.intra_expt_dp is not None else self.expt_dp
            )
        replica_groups = self.parameter_replica_groups or {}
        if domain not in replica_groups:
            raise ValueError(
                f"No replica process group is registered for parameter domain {domain!r}; "
                f"registered extra domains: {sorted(replica_groups)}"
            )
        return replica_groups[domain]

    def __repr__(self):
        """Return a concise representation showing which process groups exist and their sizes."""
        active_pgs = []
        for field_info in fields(self):
            if field_info.name not in vars(self):
                continue
            pg = getattr(self, field_info.name)
            if pg is None:
                continue
            elif isinstance(pg, list):
                sizes = [g.size() for g in pg]
                active_pgs.append(f"{field_info.name}({sizes})")
            elif isinstance(pg, dict):
                if pg:
                    sizes = {key: group.size() for key, group in sorted(pg.items())}
                    active_pgs.append(f"{field_info.name}({sizes})")
            else:
                active_pgs.append(f"{field_info.name}({pg.size()})")
        return (
            f"ProcessGroupCollection({', '.join(active_pgs)})"
            if active_pgs
            else "ProcessGroupCollection(empty)"
        )

    def __deepcopy__(self, memo):
        """Preserve runtime process-group handles when copying owning configuration objects."""
        memo[id(self)] = self
        return self

    @classmethod
    def use_mpu_process_groups(cls, required_pgs: Optional[List[str]] = None):
        """
        Use the default process groups from parallel_state.

        Args:
            required_pgs (List[str], optional): List of process group names to initialize.
                If None, pull all default process groups. Each string should correspond to
                one of the dataclass process group attributes.
        """
        # Get all available process groups
        all_pgs = {field.name for field in fields(cls)}

        # If no specific process groups requested, use all
        if required_pgs is None:
            required_pgs = list(all_pgs)

        # Validate requested process groups
        invalid_pgs = [pg for pg in required_pgs if pg not in all_pgs]
        if invalid_pgs:
            raise ValueError(f"Invalid process groups requested: {invalid_pgs}")

        # Mapping of attribute names to their initialization functions
        pg_to_func = {
            'tp': partial(parallel_state.get_tensor_model_parallel_group, check_initialized=False),
            'pp': partial(
                parallel_state.get_pipeline_model_parallel_group, check_initialized=False
            ),
            'mp': partial(parallel_state.get_model_parallel_group, check_initialized=False),
            'cp': partial(parallel_state.get_context_parallel_group, check_initialized=False),
            'dynamic_cp': parallel_state.get_dynamic_data_context_parallel_group_map,
            'dynamic_tp_cp': parallel_state.get_dynamic_tensor_data_context_parallel_group_map,
            'tp_cp': partial(
                parallel_state.get_tensor_and_context_parallel_group, check_initialized=False
            ),
            'hcp': partial(
                parallel_state.get_hierarchical_context_parallel_groups, check_initialized=False
            ),
            'ep': partial(parallel_state.get_expert_model_parallel_group, check_initialized=False),
            'expt_tp': partial(
                parallel_state.get_expert_tensor_parallel_group, check_initialized=False
            ),
            'tp_ep': partial(
                parallel_state.get_expert_tensor_and_model_parallel_group, check_initialized=False
            ),
            'tp_ep_pp': partial(
                parallel_state.get_expert_tensor_model_pipeline_parallel_group,
                check_initialized=False,
            ),
            'tp_ep_pp_with_egtp_remat': partial(
                parallel_state.get_expert_tensor_model_pipeline_parallel_group,
                check_initialized=False,
                with_egtp_remat=True,
            ),
            'embd': partial(parallel_state.get_embedding_group, check_initialized=False),
            'pos_embd': partial(
                parallel_state.get_position_embedding_group, check_initialized=False
            ),
            'dp': partial(parallel_state.get_data_parallel_group, with_gtp_remat=False),
            'dp_gtp_remat': partial(parallel_state.get_data_parallel_group, with_gtp_remat=True),
            'dp_cp': partial(
                parallel_state.get_data_parallel_group,
                with_context_parallel=True,
                with_gtp_remat=False,
            ),
            'dp_cp_gtp_remat': partial(
                parallel_state.get_data_parallel_group, with_context_parallel=True
            ),
            'dp_cp_ag': lambda: None,
            'intra_dp_cp': partial(
                parallel_state.get_data_parallel_group,
                with_context_parallel=True,
                with_gtp_remat=False,
                partial_data_parallel=True,
            ),
            'intra_expt_dp': partial(
                parallel_state.get_expert_data_parallel_group,
                check_initialized=False,
                with_gtp_remat=False,
                partial_expert_data_parallel=True,
            ),
            'inter_dist_opt': partial(
                parallel_state.get_inter_distributed_optimizer_instance_group,
                check_initialized=False,
            ),
            'intra_dist_opt': partial(
                parallel_state.get_intra_distributed_optimizer_instance_group,
                check_initialized=False,
            ),
            # TODO (Hepteract): remove this once distributed checkpoint is refactored
            'expt_dp': partial(
                parallel_state.get_expert_data_parallel_group,
                check_initialized=False,
                with_gtp_remat=False,
            ),
            'expt_dp_gtp_remat': partial(
                parallel_state.get_expert_data_parallel_group, check_initialized=False
            ),
            'expt_dp_ag': lambda: None,
            'tp_dp_cp': partial(
                parallel_state.get_tensor_and_data_parallel_group,
                check_initialized=False,
                with_context_parallel=True,
            ),
            'gtp_remat': partial(
                parallel_state.get_gtp_weight_remat_group, check_initialized=False
            ),
            'expt_gtp_remat': partial(
                parallel_state.get_expert_gtp_weight_remat_group, check_initialized=False
            ),
            # Created by model builders when a model registers an extra parameter domain.
            'engram': lambda: None,
            'engram_dp': lambda: None,
            'parameter_replica_groups': dict,
        }

        assert all(
            pg in pg_to_func for pg in required_pgs
        ), f"Initialization function for process group not defined for all \
        ProcessGroupCollection fields"

        # Build initialization dict by calling appropriate parallel_state get_foo_group
        init_dict = {pg: pg_to_func[pg]() for pg in required_pgs}

        return cls(**init_dict)

    @staticmethod
    def is_gtp_remat_active(process_group_dict: Dict) -> bool:
        """True iff GTP_remat or EGTP_remat is active (a weight-shard group spans >1 rank).

        Reads 'gtp_remat_group'/'expt_gtp_remat_group' from setup_process_groups_for_*
        builders; a None group means that axis is unused.
        """
        gtp_remat = process_group_dict.get('gtp_remat_group')
        expt_gtp_remat = process_group_dict.get('expt_gtp_remat_group')
        return (gtp_remat is not None and gtp_remat.size() > 1) or (
            expt_gtp_remat is not None and expt_gtp_remat.size() > 1
        )

    @staticmethod
    def setup_process_groups_for_optimizer(
        pg_collection: Optional['ProcessGroupCollection'],
        model_chunks: List,
        use_gloo_process_groups: bool = True,
    ):
        """
        Helper method to set up process groups for optimizer and DDP with proper validation
        and fallbacks.

        Args:
            pg_collection: Optional process group collection. If None, uses parallel_state groups.
            model_chunks: List of model chunks to extract configuration from.
            use_gloo_process_groups: Whether to set up gloo process groups.

        Returns:
            Dictionary containing all required process groups:
                - dp_group: Data parallel group
                - dp_cp_group: Data parallel with context parallel group
                - intra_dp_cp_group: Intra data parallel with context parallel group
                - expt_dp_group: Expert data parallel group
                - intra_expt_dp_group: Intra expert data parallel group
                - mp_group: Model parallel group
                - expt_tp_pp_group: Expert tensor-model-pipeline parallel group
                - inter_dist_opt_group: Inter distributed optimizer group (may be None)
                - intra_dist_opt_group: Intra distributed optimizer group (may be None)
                - intra_dp_cp_group_gloo: Gloo version of intra_dp_cp_group (may be None)
                - intra_expt_dp_group_gloo: Gloo version of intra_expt_dp_group (may be None)
        """
        from megatron.core import parallel_state
        from megatron.core.utils import get_model_config

        if pg_collection is None:
            # Use parallel_state groups
            dp_group = parallel_state.get_data_parallel_group(
                with_context_parallel=False, with_gtp_remat=False, partial_data_parallel=False
            )
            dp_cp_group = parallel_state.get_data_parallel_group(
                with_context_parallel=True, with_gtp_remat=False, partial_data_parallel=False
            )
            intra_dp_cp_group = parallel_state.get_data_parallel_group(
                with_context_parallel=True, with_gtp_remat=False, partial_data_parallel=True
            )
            expt_dp_group = parallel_state.get_expert_data_parallel_group(with_gtp_remat=False)
            intra_expt_dp_group = parallel_state.get_expert_data_parallel_group(
                with_gtp_remat=False, partial_expert_data_parallel=True
            )
            gtp_remat_group = parallel_state.get_gtp_weight_remat_group(check_initialized=False)
            expt_gtp_remat_group = parallel_state.get_expert_gtp_weight_remat_group(
                check_initialized=False
            )
            intra_dist_opt_group = parallel_state.get_intra_distributed_optimizer_instance_group()

            # Gloo is not built under GTP_remat (the GTP_remat optimizer uses DCP); fetching the
            # absent group would assert, so gate on gtp_active and leave the Gloo groups None.
            gtp_active = (gtp_remat_group is not None and gtp_remat_group.size() > 1) or (
                expt_gtp_remat_group is not None and expt_gtp_remat_group.size() > 1
            )
            if use_gloo_process_groups and not gtp_active:
                intra_dp_cp_group_gloo = parallel_state.get_data_parallel_group_gloo(
                    with_context_parallel=True, partial_data_parallel=True
                )
                intra_expt_dp_group_gloo = parallel_state.get_expert_data_parallel_group_gloo(
                    partial_expert_data_parallel=True
                )
            else:
                intra_dp_cp_group_gloo = None
                intra_expt_dp_group_gloo = None

            # Model communication groups
            mp_group = parallel_state.get_model_parallel_group()
            expt_tp_pp_group = parallel_state.get_expert_tensor_model_pipeline_parallel_group()
            expt_tp_pp_with_egtp_remat_group = (
                parallel_state.get_expert_tensor_model_pipeline_parallel_group(with_egtp_remat=True)
            )

            # Inter distributed optimizer group
            if hasattr(model_chunks[0], 'ddp_config'):
                ddp_config = model_chunks[0].ddp_config
                if ddp_config.num_distributed_optimizer_instances > 1:
                    inter_dist_opt_group = (
                        parallel_state.get_inter_distributed_optimizer_instance_group()
                    )
                else:
                    inter_dist_opt_group = None
            else:
                inter_dist_opt_group = None

        else:
            # Use provided process group collection with validation and fallbacks
            pg_set = vars(pg_collection)

            # 1. dp group - this is always required
            if 'dp' not in pg_set:
                raise ValueError("dp process group is required but not provided in pg_collection")
            dp_group = pg_collection.dp

            # 2. dp_cp group: fallback logic based on context_parallel_size
            if 'dp_cp' in pg_set:
                dp_cp_group = pg_collection.dp_cp
            else:
                model_config = get_model_config(model_chunks[0])
                cp_size = getattr(model_config, 'context_parallel_size', 1)
                if cp_size == 1:
                    # If no context parallelism, dp_cp is same as dp
                    dp_cp_group = dp_group
                else:
                    raise ValueError(
                        "dp_cp process group is required when context_parallel_size > 1 "
                        "but not provided in pg_collection"
                    )

            # 3. Handle expert data parallel group
            if 'expt_dp' not in pg_set:
                raise ValueError(
                    "expt_dp process group is required but not provided in pg_collection. "
                    "Please explicitly set it to None if you don't need it."
                )
            expt_dp_group = pg_collection.expt_dp

            # 4. Handle intra_dp_cp, intra_expt_dp, and inter_dist_opt based on optimizer instances
            if hasattr(model_chunks[0], 'ddp_config'):
                ddp_config = model_chunks[0].ddp_config
                if ddp_config.num_distributed_optimizer_instances == 1:
                    # With a single optimizer instance:
                    # - intra_dp_cp is same as dp_cp
                    # - intra_expt_dp is same as expt_dp
                    # - inter_dist_opt is not needed (set to None)
                    intra_dp_cp_group = dp_cp_group
                    intra_expt_dp_group = expt_dp_group
                    inter_dist_opt_group = None
                else:
                    # With multiple optimizer instances, both groups must be provided
                    if not (
                        'intra_dp_cp' in pg_set
                        and 'intra_expt_dp' in pg_set
                        and 'inter_dist_opt' in pg_set
                        and 'intra_dist_opt' in pg_set
                    ):
                        raise ValueError(
                            "intra_dp_cp, intra_expt_dp, inter_dist_opt, and intra_dist_opt "
                            "process groups are required when using multiple optimizer "
                            "instances (>1) but not provided in pg_collection"
                        )
                    intra_dp_cp_group = pg_collection.intra_dp_cp
                    intra_expt_dp_group = pg_collection.intra_expt_dp
                    inter_dist_opt_group = pg_collection.inter_dist_opt

                if ddp_config.use_distributed_optimizer:
                    if 'intra_dist_opt' not in pg_set:
                        raise ValueError(
                            "intra_dist_opt process group is required but not provided in "
                            "pg_collection. Please explicitly set it to None if you don't need it."
                        )
                    intra_dist_opt_group = pg_collection.intra_dist_opt
                else:
                    intra_dist_opt_group = None
            else:
                # No ddp_config available - use simple fallback
                intra_dp_cp_group = dp_cp_group
                intra_expt_dp_group = expt_dp_group
                inter_dist_opt_group = None
                intra_dist_opt_group = None

            # 5. Model communication groups
            if 'mp' not in pg_set:
                raise ValueError(
                    "mp process group is required but not provided in pg_collection. "
                    "Please explicitly set it to None if you don't need it."
                )
            mp_group = pg_collection.mp

            # Expert tensor-model-pipeline group for MoE
            if 'tp_ep_pp' not in pg_set:
                raise ValueError(
                    "tp_ep_pp process group is required but not provided in pg_collection. "
                    "Please explicitly set it to None if you don't need it."
                )
            expt_tp_pp_group = pg_collection.tp_ep_pp

            # EGTP-MERGED variant of tp_ep_pp: includes the egtp axis, so each EGTP peer gets a
            # distinct rank — used for the distopt ShardedObject keys. Falls back to tp_ep_pp
            # when not provided.
            if 'tp_ep_pp_with_egtp_remat' in pg_set:
                expt_tp_pp_with_egtp_remat_group = pg_collection.tp_ep_pp_with_egtp_remat
            else:
                expt_tp_pp_with_egtp_remat_group = expt_tp_pp_group

            # GTP weight-shard groups (None when inactive); used to detect whether GTP is on.
            gtp_remat_group = getattr(pg_collection, 'gtp_remat', None)
            expt_gtp_remat_group = getattr(pg_collection, 'expt_gtp_remat', None)

            # Gloo groups - not supported when pg_collection is provided
            if use_gloo_process_groups:
                raise ValueError(
                    "Gloo process groups are not supported when pg_collection is "
                    "provided. Please set use_gloo_process_groups to False."
                )
            intra_dp_cp_group_gloo = None
            intra_expt_dp_group_gloo = None

        return {
            'dp_group': dp_group,
            'dp_cp_group': dp_cp_group,
            'intra_dp_cp_group': intra_dp_cp_group,
            'expt_dp_group': expt_dp_group,
            'intra_expt_dp_group': intra_expt_dp_group,
            'gtp_remat_group': gtp_remat_group,
            'expt_gtp_remat_group': expt_gtp_remat_group,
            'mp_group': mp_group,
            'expt_tp_pp_group': expt_tp_pp_group,
            'expt_tp_pp_with_egtp_remat_group': expt_tp_pp_with_egtp_remat_group,
            'inter_dist_opt_group': inter_dist_opt_group,
            'intra_dist_opt_group': intra_dist_opt_group,
            'intra_dp_cp_group_gloo': intra_dp_cp_group_gloo,
            'intra_expt_dp_group_gloo': intra_expt_dp_group_gloo,
        }

    @staticmethod
    def setup_process_groups_for_ddp(
        pg_collection: Optional['ProcessGroupCollection'], config, ddp_config
    ):
        """
        Helper method to set up process groups for DDP with proper validation and fallbacks.

        Args:
            pg_collection: Optional process group collection. If None, uses parallel_state groups.
            config: Model config to extract context_parallel_size from.
            ddp_config: DDP config to extract num_distributed_optimizer_instances from.

        Returns:
            Dictionary containing all required process groups for DDP.
        """
        import logging

        import torch

        from megatron.core import parallel_state
        from megatron.core.utils import log_single_rank

        logger = logging.getLogger(__name__)

        if pg_collection is None:
            # Use parallel_state groups
            return {
                'dp_group': parallel_state.get_data_parallel_group(
                    with_context_parallel=False, with_gtp_remat=False, partial_data_parallel=False
                ),
                'dp_cp_group': parallel_state.get_data_parallel_group(
                    with_context_parallel=True, with_gtp_remat=False, partial_data_parallel=False
                ),
                'intra_dp_cp_group': parallel_state.get_data_parallel_group(
                    with_context_parallel=True, with_gtp_remat=False, partial_data_parallel=True
                ),
                'expt_dp_group': parallel_state.get_expert_data_parallel_group(
                    with_gtp_remat=False
                ),
                'intra_expt_dp_group': parallel_state.get_expert_data_parallel_group(
                    with_gtp_remat=False, partial_expert_data_parallel=True
                ),
                'tp_group': parallel_state.get_tensor_model_parallel_group(),
                'gtp_remat_group': parallel_state.get_gtp_weight_remat_group(
                    check_initialized=False
                ),
                'pp_group': parallel_state.get_pipeline_model_parallel_group(),
                'ep_group': parallel_state.get_expert_model_parallel_group(),
                'expt_gtp_remat_group': parallel_state.get_expert_gtp_weight_remat_group(
                    check_initialized=False
                ),
                'inter_dist_opt_group': (
                    parallel_state.get_inter_distributed_optimizer_instance_group()
                    if ddp_config.num_distributed_optimizer_instances > 1
                    else None
                ),
                'intra_dist_opt_group': (
                    parallel_state.get_intra_distributed_optimizer_instance_group()
                    if ddp_config.use_distributed_optimizer
                    else None
                ),
                # Extra parameter domains are registered on a pg_collection by model builders.
                'parameter_replica_groups': {},
            }
        else:
            # Use provided process group collection with validation and fallbacks
            result = {}
            pg_set = vars(pg_collection)

            # 1. dp group - this is always required
            if 'dp' not in pg_set:
                raise ValueError("dp process group is required but not provided in pg_collection")
            result['dp_group'] = pg_collection.dp

            # 2. dp_cp group: fallback logic based on context_parallel_size
            if 'dp_cp' in pg_set:
                result['dp_cp_group'] = pg_collection.dp_cp
            else:
                cp_size = getattr(config, 'context_parallel_size', 1)
                if cp_size == 1:
                    # If no context parallelism, dp_cp is same as dp
                    result['dp_cp_group'] = result['dp_group']
                else:
                    raise ValueError(
                        "dp_cp process group is required when context_parallel_size > 1 "
                        "but not provided in pg_collection"
                    )

            # 3. Handle expert data parallel group (DDP-specific: create if missing)
            if hasattr(pg_collection, 'expt_dp') and pg_collection.expt_dp is not None:
                result['expt_dp_group'] = pg_collection.expt_dp
            else:
                # Create a new group with just the current rank for DDP
                log_single_rank(
                    logger,
                    logging.WARNING,
                    "No expert data parallel group provided in pg_collection, "
                    "creating a new one with just the current rank",
                )
                result['expt_dp_group'] = torch.distributed.new_group(
                    ranks=[torch.distributed.get_rank()]
                )

            # 4. Handle intra groups based on optimizer instances
            if ddp_config.num_distributed_optimizer_instances == 1:
                result['intra_dp_cp_group'] = result['dp_cp_group']
                result['intra_expt_dp_group'] = result['expt_dp_group']
                result['inter_dist_opt_group'] = None
            else:
                # With multiple optimizer instances, groups must be provided
                if not (
                    'intra_dp_cp' in pg_set
                    and 'intra_expt_dp' in pg_set
                    and 'inter_dist_opt' in pg_set
                ):
                    raise ValueError(
                        "intra_dp_cp, intra_expt_dp, and inter_dist_opt "
                        "process groups are required when using multiple optimizer "
                        "instances (>1) but not provided in pg_collection"
                    )
                result['intra_dp_cp_group'] = pg_collection.intra_dp_cp
                result['intra_expt_dp_group'] = pg_collection.intra_expt_dp
                result['inter_dist_opt_group'] = pg_collection.inter_dist_opt

            # 5. Model parallel groups (DDP-specific: tp, pp, ep instead of mp, expt_tp_pp)
            if not all(['tp' in pg_set, 'pp' in pg_set, 'ep' in pg_set]):
                raise ValueError(
                    "tp, pp and ep process groups are required but not provided in pg_collection"
                )
            result['tp_group'] = pg_collection.tp
            result['pp_group'] = pg_collection.pp
            result['ep_group'] = pg_collection.ep

            # GTP weight-shard groups (None when inactive); used to detect whether GTP is on.
            result['gtp_remat_group'] = getattr(pg_collection, 'gtp_remat', None)
            result['expt_gtp_remat_group'] = getattr(pg_collection, 'expt_gtp_remat', None)

            # Replica groups of the extra parameter domains, if the model registered any.
            result['parameter_replica_groups'] = dict(
                getattr(pg_collection, 'parameter_replica_groups', None) or {}
            )

            return result


def resolve_gtp_remat_group(
    pg_collection: Optional[Union["ProcessGroupCollection", "MultiModuleProcessGroupCollection"]],
    is_expert: bool,
) -> Optional[torch.distributed.ProcessGroup]:
    """Resolve the gtp_remat / expt_gtp_remat group for a weight-owning module.

    Prefers the group carried by ``pg_collection``; falls back to the MPU globals when the
    caller passed no collection, or one predating the gtp_remat fields. The fallback keeps
    pre-pg_collection callers working — a collection that does carry the field is always
    honored, including when it holds a custom (non-MPU) group.

    A ``MultiModuleProcessGroupCollection`` is unwrapped to the language model's collection
    first: only the per-module collections carry the GTP axes, so the wrapper would
    otherwise miss the ``vars()`` check below and fall through to MPU globals that a MIMO
    run never creates.

    Args:
        pg_collection: Collection supplied by the caller, or None.
        is_expert: Select the expert axis (``expt_gtp_remat``) instead of the dense one.
    """
    attr = 'expt_gtp_remat' if is_expert else 'gtp_remat'
    if isinstance(pg_collection, MultiModuleProcessGroupCollection):
        # Ranks outside the language module (a MIMO vision encoder) own no GTP axis, and
        # get_language_model_collection() raises for them, so answer None directly.
        if pg_collection.language_model_module_name is None:
            return None
        pg_collection = pg_collection.get_language_model_collection()
    # `vars()`, not hasattr: __getattr__ makes hasattr always True, so the fallback below
    # would be unreachable.
    if pg_collection is not None and attr in vars(pg_collection):
        return getattr(pg_collection, attr)
    mpu_pgs = ProcessGroupCollection.use_mpu_process_groups(
        required_pgs=['gtp_remat', 'expt_gtp_remat']
    )
    return getattr(mpu_pgs, attr)


@dataclass
class MultiModuleProcessGroupCollection:
    """Process group collection for multi-module pipelines.

    Used when a rank participates in multiple modules (e.g., colocated encoder + LLM).
    The language_model_module_name identifies which module is the language model (used for
    CP size extraction, loss computation, and other LLM-specific operations).

    Attributes:
        module_pgs: Dict mapping module names to ProcessGroupCollection objects
        language_model_module_name: Key identifying the language model module
            (None if no LLM on this rank)

    Example:
        # Colocated rank with encoder and LLM
        pg_collection = MultiModuleProcessGroupCollection(
            module_pgs={"encoder": encoder_pg, "llm": llm_pg},
            language_model_module_name="llm"
        )

        # Rank with dual encoders (no LLM)
        pg_collection = MultiModuleProcessGroupCollection(
            module_pgs={"encoder_1": encoder_1_pg, "encoder_2": encoder_2_pg},
            language_model_module_name=None
        )

        # Single module (can also use ProcessGroupCollection directly)
        pg_collection = MultiModuleProcessGroupCollection(
            module_pgs={"llm": llm_pg},
            language_model_module_name="llm"
        )

        # Usage
        cp_size = pg_collection.get_language_model_cp_size()
        encoder_pg = pg_collection["encoder_1"]  # Dict-like access
        has_llm = pg_collection.has_language_model()
    """

    module_pgs: Dict[str, ProcessGroupCollection]
    language_model_module_name: Optional[str] = None

    def __post_init__(self):
        if not self.module_pgs:
            raise ValueError("module_pgs dict cannot be empty")
        if self.language_model_module_name is not None:
            if self.language_model_module_name not in self.module_pgs:
                raise ValueError(
                    f"language_model_module_name '{self.language_model_module_name}' not found in "
                    f"module_pgs keys: {list(self.module_pgs.keys())}"
                )

    def get_language_model_collection(self) -> ProcessGroupCollection:
        """Get the language model's process group collection.

        Returns:
            ProcessGroupCollection for the language model.

        Raises:
            ValueError: If no language model is specified for this collection.
        """
        if self.language_model_module_name is None:
            raise ValueError("No language model specified for this collection")
        return self.module_pgs[self.language_model_module_name]

    def get_language_model_cp_size(self) -> int:
        """Get context parallel size for the language model.

        Returns:
            Context parallel size for the language model.

        Raises:
            ValueError: If no language model is specified for this collection.
        """
        return self.get_language_model_collection().cp.size()

    def has_language_model(self) -> bool:
        """Check if this rank has a language model.

        Returns:
            True if this rank has a language model, False otherwise.
        """
        return self.language_model_module_name is not None

    def get_module_collection(self, module_name: str) -> ProcessGroupCollection:
        """Get process group collection for a specific module.

        Args:
            module_name: Name of the module.

        Returns:
            ProcessGroupCollection for the specified module.

        Raises:
            ValueError: If module_name is not found in collections.
        """
        if module_name not in self.module_pgs:
            raise ValueError(
                f"Module '{module_name}' not found in collections. "
                f"Available: {list(self.module_pgs.keys())}"
            )
        return self.module_pgs[module_name]

    def __len__(self):
        """Return the number of modules in this wrapper."""
        return len(self.module_pgs)

    def __getitem__(self, module_name: str):
        """Get process group collection for a module using dict-like access."""
        return self.module_pgs[module_name]

    def __iter__(self):
        """Iterate over all process group collections."""
        return iter(self.module_pgs.values())

    def keys(self):
        """Return module names."""
        return self.module_pgs.keys()

    def values(self):
        """Return process group collections."""
        return self.module_pgs.values()

    def items(self):
        """Return (module_name, collection) pairs."""
        return self.module_pgs.items()

    def __repr__(self):
        """Return a concise representation showing modules and their language model status."""
        modules_str = ', '.join(self.module_pgs.keys())
        lm_str = (
            f", language_model_module_name='{self.language_model_module_name}'"
            if self.language_model_module_name
            else ""
        )
        return f"MultiModuleProcessGroupCollection(modules=[{modules_str}]{lm_str})"

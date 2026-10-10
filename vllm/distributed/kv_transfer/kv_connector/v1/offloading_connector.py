# SPDX-License-Identifier: Apache-2.0
# SPDX-FileCopyrightText: Copyright contributors to the vLLM project
from collections.abc import Iterable
from functools import cached_property
from typing import TYPE_CHECKING, Any

import torch

from vllm.config import VllmConfig
from vllm.distributed.kv_events import KVCacheEvent
from vllm.distributed.kv_transfer.kv_connector.v1 import (
    KVConnectorBase_V1,
    KVConnectorRole,
    SupportsHMA,
)
from vllm.distributed.kv_transfer.kv_connector.v1.base import KVConnectorMetadata
from vllm.distributed.kv_transfer.kv_connector.v1.metrics import (
    KVConnectorPromMetrics,
    KVConnectorStats,
    PromMetric,
    PromMetricT,
)
from vllm.distributed.kv_transfer.kv_connector.v1.offloading.common import (
    OffloadingConnectorMetadata,
    OffloadingWorkerMetadata,
)
from vllm.distributed.kv_transfer.kv_connector.v1.offloading.config import (
    build_offloading_config,
    get_offloading_group_ids,
)
from vllm.distributed.kv_transfer.kv_connector.v1.offloading.metrics import (
    OffloadingConnectorStats,
    OffloadPromMetrics,
)
from vllm.distributed.kv_transfer.kv_connector.v1.offloading.scheduler import (
    OffloadingConnectorScheduler,
)
from vllm.distributed.kv_transfer.kv_connector.v1.offloading.worker import (
    OffloadingConnectorWorker,
)
from vllm.forward_context import ForwardContext
from vllm.v1.attention.backend import AttentionMetadata
from vllm.v1.core.kv_cache_coordinator import HybridKVCacheCoordinator
from vllm.v1.core.kv_cache_manager import KVCacheBlocks
from vllm.v1.core.sched.output import SchedulerOutput
from vllm.v1.kv_cache_interface import FullAttentionSpec, KVCacheConfig, MambaSpec
from vllm.v1.kv_offload.factory import OffloadingSpecFactory
from vllm.v1.metrics.cache_hit_source import CacheHitSource
from vllm.v1.outputs import KVConnectorOutput
from vllm.v1.request import Request

if TYPE_CHECKING:
    from vllm.v1.core.kv_cache_manager import KVCacheManager


class OffloadingConnector(KVConnectorBase_V1, SupportsHMA):
    _gpu_prefix_group_ids: tuple[int, ...] = ()

    @cached_property
    def _bounding_group_ids(self) -> tuple[int, ...]:
        """Prefix-cacheable groups this connector does not offload.

        Never offer tokens for a range some group cannot cover: past such a
        group's own cached prefix its KV would be left unwritten.
        """
        offloaded = set(get_offloading_group_ids(self._kv_cache_config))
        return tuple(
            group_id
            for group_id, group in enumerate(self._kv_cache_config.kv_cache_groups)
            if group.kv_cache_spec.prefix_cacheable and group_id not in offloaded
        )

    @property
    def scheduler(self) -> OffloadingConnectorScheduler:
        assert self.connector_scheduler is not None
        return self.connector_scheduler

    @property
    def requires_kv_delivery(self) -> bool:
        # Runs as kv_both, but is a best-effort cache: a dropped save is just a
        # future cache miss, so opt out of the producer-role default.
        return False

    def __init__(
        self,
        vllm_config: VllmConfig,
        role: KVConnectorRole,
        kv_cache_config: KVCacheConfig,
    ):
        super().__init__(vllm_config, role, kv_cache_config)

        offloading_config = build_offloading_config(vllm_config, kv_cache_config)
        self._canonical_layout = offloading_config.canonical_layout
        spec = OffloadingSpecFactory.create_spec(offloading_config)

        self.connector_scheduler: OffloadingConnectorScheduler | None = None
        self.connector_worker: OffloadingConnectorWorker | None = None
        if role == KVConnectorRole.SCHEDULER:
            self.connector_scheduler = OffloadingConnectorScheduler(
                spec, vllm_config, kv_cache_config
            )
        elif role == KVConnectorRole.WORKER:
            self.connector_worker = OffloadingConnectorWorker(
                spec, vllm_config, kv_cache_config
            )

    def shutdown(self) -> None:
        if self.connector_worker is not None:
            self.connector_worker.shutdown()
        if self.connector_scheduler is not None:
            self.connector_scheduler.shutdown()

    def register_kv_caches(self, kv_caches: dict[str, torch.Tensor]):
        assert self.connector_worker is not None
        self.connector_worker.register_kv_caches(kv_caches)

    def handle_preemptions(self, kv_connector_metadata: KVConnectorMetadata):
        assert self.connector_worker is not None
        assert isinstance(kv_connector_metadata, OffloadingConnectorMetadata)
        self.connector_worker.handle_preemptions(kv_connector_metadata)

    def start_load_kv(self, forward_context: "ForwardContext", **kwargs) -> None:
        assert self.connector_worker is not None
        assert isinstance(self._connector_metadata, OffloadingConnectorMetadata)
        self.connector_worker.start_kv_transfers(self._connector_metadata)

    def wait_for_layer_load(self, layer_name: str) -> None:
        pass

    def save_kv_layer(
        self,
        layer_name: str,
        kv_layer: torch.Tensor,
        attn_metadata: "AttentionMetadata",
        **kwargs,
    ) -> None:
        pass

    def wait_for_save(self):
        assert self.connector_worker is not None
        assert isinstance(self._connector_metadata, OffloadingConnectorMetadata)
        # Defer store jobs to the next step's start_kv_transfers.
        self.connector_worker.prepare_store_kv(self._connector_metadata)

    def get_finished(self, finished_req_ids: set[str]) -> tuple[set[str], set[str]]:
        assert self.connector_worker is not None
        assert isinstance(self._connector_metadata, OffloadingConnectorMetadata)
        return self.connector_worker.get_finished(finished_req_ids)

    def build_connector_worker_meta(self) -> OffloadingWorkerMetadata | None:
        if self.connector_worker is not None:
            return self.connector_worker.build_connector_worker_meta()
        return None

    def on_new_request(self, request: "Request") -> None:
        assert self.connector_scheduler is not None
        self.connector_scheduler.on_new_request(request)

    def bind_kv_cache_manager(self, kv_cache_manager: "KVCacheManager") -> None:
        """Retain complete GPU attention prefixes for per-group CPU lookup."""
        super().bind_kv_cache_manager(kv_cache_manager)
        coordinator = kv_cache_manager.coordinator
        if (
            self.connector_scheduler is None
            or not kv_cache_manager.enable_caching
            or not isinstance(coordinator, HybridKVCacheCoordinator)
        ):
            return

        config = self.scheduler.config
        groups = config.kv_group_configs
        if (
            config.blocks_per_chunk != 1
            or {group.group_idx for group in groups}
            != set(kv_cache_manager.kv_cache_config.prefix_cacheable_group_ids)
            or len({group.tokens_per_block for group in groups}) != 1
            or not any(
                isinstance(group.kv_cache_spec, FullAttentionSpec) for group in groups
            )
            or not any(isinstance(group.kv_cache_spec, MambaSpec) for group in groups)
            or any(
                not isinstance(group.kv_cache_spec, (FullAttentionSpec, MambaSpec))
                or (
                    isinstance(group.kv_cache_spec, MambaSpec)
                    and group.kv_cache_spec.mamba_cache_mode != "align"
                )
                or coordinator.single_type_managers[group.group_idx].block_size
                != group.tokens_per_block
                for group in groups
            )
        ):
            return

        self._gpu_prefix_group_ids = tuple(
            group.group_idx
            for group in groups
            if isinstance(group.kv_cache_spec, FullAttentionSpec)
        )
        for group_id in self._gpu_prefix_group_ids:
            manager = coordinator.single_type_managers[group_id]
            manager.retains_longer_hit = True
            manager.retains_complete_hit = True
        kv_cache_manager.retained_hit_group_ids = tuple(
            dict.fromkeys(
                (*kv_cache_manager.retained_hit_group_ids, *self._gpu_prefix_group_ids)
            )
        )

    def get_num_new_matched_tokens(
        self, request: "Request", num_computed_tokens: int
    ) -> tuple[int | None, bool]:
        assert self.connector_scheduler is not None
        gpu_prefix_tokens = None
        if self._gpu_prefix_group_ids and not request.skip_reading_prefix_cache:
            assert self._kv_cache_manager is not None
            coordinator = self._kv_cache_manager.coordinator
            assert isinstance(coordinator, HybridKVCacheCoordinator)
            _, shared_gpu_hit, _ = coordinator.find_longest_cache_hit(
                request.block_hashes, request.num_tokens - 1
            )
            if shared_gpu_hit == num_computed_tokens:
                _, per_group_hits = coordinator.find_longest_cache_hit_per_group(
                    request.block_hashes, request.num_tokens - 1
                )
                gpu_prefix_tokens = {
                    group.group_idx: (
                        per_group_hits[group.group_idx]
                        // group.tokens_per_chunk
                        * group.tokens_per_chunk
                    )
                    for group in self.scheduler.config.kv_group_configs
                    if group.group_idx in self._gpu_prefix_group_ids
                }
        return self.connector_scheduler.get_num_new_matched_tokens(
            request,
            num_computed_tokens,
            max_num_new_tokens=self._max_loadable_tokens(request, num_computed_tokens),
            gpu_prefix_tokens=gpu_prefix_tokens,
        )

    def _max_loadable_tokens(
        self, request: "Request", num_computed_tokens: int
    ) -> int | None:
        """How far past ``num_computed_tokens`` a load may reach, if bounded.

        Bounded by the deepest prefix the groups this connector does not
        offload already hold, since nothing refills them beyond it.
        """
        if not self._bounding_group_ids:
            return None
        assert self._kv_cache_manager is not None
        coordinator = self._kv_cache_manager.coordinator
        assert isinstance(coordinator, HybridKVCacheCoordinator)
        _, per_group_hits = coordinator.find_longest_cache_hit_per_group(
            request.block_hashes, request.num_tokens - 1
        )
        bound = min(per_group_hits[group_id] for group_id in self._bounding_group_ids)
        return max(0, bound - num_computed_tokens)

    def get_external_cache_hit_sources(
        self,
        request: "Request",
        num_external_tokens: int,
    ) -> dict[CacheHitSource, int]:
        assert self.connector_scheduler is not None
        return self.connector_scheduler.get_external_cache_hit_sources(
            request, num_external_tokens
        )

    def update_state_after_alloc(
        self, request: "Request", blocks: "KVCacheBlocks", num_external_tokens: int
    ):
        assert self.connector_scheduler is not None
        return self.connector_scheduler.update_state_after_alloc(
            request, blocks, num_external_tokens
        )

    def build_connector_meta(
        self, scheduler_output: SchedulerOutput
    ) -> KVConnectorMetadata:
        assert self.connector_scheduler is not None
        return self.connector_scheduler.build_connector_meta(scheduler_output)

    def has_pending_push_work(self) -> bool:
        assert self.connector_scheduler is not None
        return self.connector_scheduler.has_pending_push_work()

    def update_connector_output(self, connector_output: KVConnectorOutput):
        assert self.connector_scheduler is not None
        self.connector_scheduler.update_connector_output(connector_output)

    def request_finished(
        self,
        request: "Request",
        block_ids: list[int],
    ) -> tuple[bool, dict[str, Any] | None]:
        assert self.connector_scheduler is not None
        return self.connector_scheduler.request_finished(request)

    def request_finished_all_groups(
        self,
        request: "Request",
        block_ids: tuple[list[int], ...],
    ) -> tuple[bool, dict[str, Any] | None]:
        assert self.connector_scheduler is not None
        return self.connector_scheduler.request_finished(request)

    def take_events(self) -> Iterable[KVCacheEvent]:
        assert self.connector_scheduler is not None
        return self.connector_scheduler.take_events()

    @classmethod
    def get_required_kvcache_layout(cls, vllm_config: VllmConfig) -> str | None:
        if vllm_config.attention_config.hisparse_config is not None:
            return "BLHNC"
        return "LBHNC"

    def reset_cache(self) -> bool | None:
        assert self.connector_scheduler is not None
        self.connector_scheduler.reset_cache()
        return True

    def get_kv_connector_stats(self) -> KVConnectorStats | None:
        if self.connector_scheduler is not None:
            return self.connector_scheduler.get_stats()
        return None

    @classmethod
    def build_kv_connector_stats(
        cls, data: dict[str, Any] | None = None
    ) -> KVConnectorStats | None:
        return (
            OffloadingConnectorStats(data=data)
            if data is not None
            else OffloadingConnectorStats()
        )

    @classmethod
    def build_prom_metrics(
        cls,
        vllm_config: VllmConfig,
        metric_types: dict[type[PromMetric], type[PromMetricT]],
        labelnames: list[str],
        per_engine_labelvalues: dict[int, list[object]],
    ) -> KVConnectorPromMetrics:
        return OffloadPromMetrics(
            vllm_config, metric_types, labelnames, per_engine_labelvalues
        )

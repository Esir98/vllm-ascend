# SPDX-License-Identifier: Apache-2.0
# SPDX-FileCopyrightText: Copyright contributors to the vLLM Ascend project

from types import SimpleNamespace
from unittest.mock import Mock, call, patch

import pytest
import torch
from vllm.distributed.kv_transfer.kv_connector.v1.base import KVConnectorRole
from vllm.v1.hisparse.layout import get_hisparse_kv_cache_groups
from vllm.v1.kv_cache_interface import KVCacheConfig, SparseCacheRole

from vllm_ascend.core.kv_cache_interface import AscendMLAAttentionSpec, AscendSFAIndexerCacheSpec
from vllm_ascend.distributed.kv_transfer.kv_pool.ascend_store.ascend_store_connector import AscendStoreConnector
from vllm_ascend.distributed.kv_transfer.kv_pool.ascend_store.backend.memcache_backend import (
    MemcacheBackend,
    MmcDirect,
)
from vllm_ascend.distributed.kv_transfer.kv_pool.ascend_store.pool_worker import KVPoolWorker
from vllm_ascend.hisparse.binding import _allocate_aligned_slab, _bind_indexer_views


def aligned_tensor(size: int) -> torch.Tensor:
    backing = torch.empty(size + 2 * 1024 * 1024, dtype=torch.int8)
    offset = -backing.data_ptr() % (2 * 1024 * 1024)
    return backing[offset : offset + size]


@pytest.mark.parametrize("indexer_c8", [False, True])
def test_hisparse_groups_register_with_independent_host_blocks(indexer_c8: bool) -> None:
    block_size = 128
    num_device_blocks = 4
    num_host_blocks = 5
    source_name = "model.layers.0.self_attn"
    indexer_name = "model.layers.0.indexer.k_cache"
    source_spec = AscendMLAAttentionSpec(
        block_size=block_size,
        num_kv_heads=1,
        head_size=128,
        dtype=torch.bfloat16,
        cache_role=SparseCacheRole.SPARSE,
    )
    indexer_spec = AscendSFAIndexerCacheSpec(
        block_size=block_size,
        num_kv_heads=1,
        head_size=128,
        dtype=torch.float8_e4m3fn if indexer_c8 else torch.bfloat16,
        cache_role=SparseCacheRole.INDEXER,
        cache_sparse_li_c8=indexer_c8,
        scale_dim=1 if indexer_c8 else 0,
        scale_dtype=torch.float32 if indexer_c8 else torch.int8,
    )
    config = SimpleNamespace(
        attention_config=SimpleNamespace(
            hisparse_config=SimpleNamespace(device_buffer_size=256, eager_host_mirror=True),
        ),
        model_config=SimpleNamespace(hf_config=SimpleNamespace(index_topk=128)),
        speculative_config=None,
    )
    groups = get_hisparse_kv_cache_groups(config, {source_name: source_spec, indexer_name: indexer_spec})
    assert groups is not None
    cache_config = KVCacheConfig(num_device_blocks, [], groups, hisparse_host_num_blocks=num_host_blocks)

    source = aligned_tensor(num_host_blocks * 32768).view(torch.bfloat16).view(num_host_blocks, 128, 1, 128)
    if indexer_c8:
        size = num_device_blocks * 17408
        alignment = 2 * 1024 * 1024
        # Force a non-aligned allocation even on hosts whose allocator happens
        # to return a huge-page-aligned address for this test.
        unaligned = aligned_tensor(size + alignment)[1:]
        with patch("vllm_ascend.hisparse.binding.torch.zeros", return_value=unaligned):
            raw = _allocate_aligned_slab(size, torch.device("cpu"))
        assert raw.data_ptr() % alignment == 0
        assert raw.storage_offset() == 0
        assert raw.untyped_storage().nbytes() == size
        indexer = torch.as_strided(raw.view(torch.float8_e4m3fn), (4, 1, 128, 132), (17408, 16896, 132, 1))
    else:
        raw = aligned_tensor(num_device_blocks * 3 * 32768)
        indexer = raw.view(torch.bfloat16).view(4, 3, 128, 128)[:, 0].view(4, 1, 128, 128)
    caches = {source_name: source, indexer_name: indexer}
    context = {source_name: SimpleNamespace(), indexer_name: SimpleNamespace()}
    _bind_indexer_views(caches, {indexer_name: indexer_spec}, context)

    worker = KVPoolWorker.__new__(KVPoolWorker)
    worker.use_recoverssm = False
    worker.kv_cache_config = cache_config
    worker.vllm_config = SimpleNamespace(compilation_config=SimpleNamespace(static_forward_context=context))
    worker.use_kvpp = False
    worker.use_hybrid = True
    worker.use_layerwise = False
    worker.use_mla = True
    worker.use_sparse = True
    worker.tp_mismatch = False
    worker.num_kv_cache_groups = len(groups)
    worker.num_layers = 1
    worker.hf_config = SimpleNamespace(num_hidden_layers=1)
    worker.kv_cache_group_families = ["default"] * len(groups)
    worker._global_to_local_layer = {}
    worker._extra_config = {}
    worker.grouped_block_size = [128] * len(groups)
    worker.cache_transfer_granularity = 128
    worker.group_uses_align_state = [False] * len(groups)
    worker.dcp_size = 1
    worker.token_database = Mock()
    worker.m_store = Mock()
    worker._start_kv_transfer_threads = Mock()

    worker.register_kv_caches(caches)
    assert worker.group_block_len[0] == [32768]
    assert worker.group_block_stride[0] == [32768]
    assert worker.group_block_len[1] == ([16384, 512] if indexer_c8 else [32768])
    assert worker.group_block_stride[1] == ([17408, 17408] if indexer_c8 else [98304])
    assert all(worker.group_block_len[index] == [] for index in range(2, len(groups)))
    worker.m_store.register_buffer.assert_called_once()
    if indexer_c8:
        ptrs, lengths = worker.m_store.register_buffer.call_args.args
        assert lengths[ptrs.index(raw.data_ptr())] == (num_device_blocks - 1) * 17408 + 16896


def test_memcache_splits_host_and_device_batches_without_reordering() -> None:
    backend = MemcacheBackend.__new__(MemcacheBackend)
    backend.store = Mock()
    backend._store_initialized = True
    backend._lazy_init = False
    backend._pending_buffers = None
    backend.set_hisparse_host_ranges([(1000, 2000)])
    backend.store.batch_put_from_layers.side_effect = [[0, -7], [0]]
    backend.store.batch_get_into_layers.side_effect = [[0, -7], [0]]

    keys = ["host", "device1", "device2"]
    addresses = [[1100], [3000], [4000]]
    sizes = [[100], [100], [100]]
    assert backend.put(keys, addresses, sizes) == [True, True, False]
    assert backend.get(keys, addresses, sizes) == [0, 0, -7]
    assert backend.store.batch_put_from_layers.call_args_list == [
        call(["device1", "device2"], [[3000], [4000]], [[100], [100]], MmcDirect.COPY_L2G.value),
        call(["host"], [[1100]], [[100]], MmcDirect.COPY_H2G.value),
    ]
    assert backend.store.batch_get_into_layers.call_args_list == [
        call(["device1", "device2"], [[3000], [4000]], [[100], [100]], MmcDirect.COPY_G2L.value),
        call(["host"], [[1100]], [[100]], MmcDirect.COPY_G2H.value),
    ]
    with pytest.raises(ValueError, match="exceeds its registered host range"):
        backend._transfer_hisparse(["bad"], [[1950]], [[100]], put=True)
    with pytest.raises(ValueError, match="exceeds its registered host range"):
        backend._transfer_hisparse(["bad"], [[950]], [[100]], put=False)
    with pytest.raises(ValueError, match="cannot combine host and device"):
        backend._transfer_hisparse(["mixed"], [[1100, 3000]], [[100, 100]], put=False)
    with pytest.raises(ValueError, match="matching key, address and size counts"):
        backend._transfer_hisparse(["missing"], [], [], put=True)


@pytest.mark.parametrize(
    ("extra_config", "kv_role"),
    [
        ({"backend": "mooncake"}, "kv_both"),
        ({"backend": "memcache", "use_layerwise": True}, "kv_both"),
        ({"backend": "memcache"}, "kv_consumer"),
    ],
)
def test_hisparse_rejects_unsupported_store_mode(extra_config, kv_role):
    config = SimpleNamespace(
        parallel_config=SimpleNamespace(),
        kv_transfer_config=SimpleNamespace(kv_role=kv_role, kv_connector_extra_config=extra_config),
    )
    cache = SimpleNamespace(kv_cache_groups=[SimpleNamespace(role="hisparse_source", layer_names=[])])
    with pytest.raises(ValueError, match="requires bulk MemCache transfers"):
        AscendStoreConnector(config, KVConnectorRole.SCHEDULER, cache)

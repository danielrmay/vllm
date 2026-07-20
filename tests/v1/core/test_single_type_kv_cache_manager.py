# SPDX-License-Identifier: Apache-2.0
# SPDX-FileCopyrightText: Copyright contributors to the vLLM project

import random

import pytest
import torch

from vllm.v1.core.block_pool import BlockPool
from vllm.v1.core.kv_cache_utils import (
    BlockHash,
    KVCacheBlock,
    make_block_hash_with_group_id,
)
from vllm.v1.core.single_type_kv_cache_manager import (
    ChunkedLocalAttentionManager,
    RSWAManager,
    SlidingWindowManager,
)
from vllm.v1.kv_cache_interface import (
    ChunkedLocalAttentionSpec,
    RSWASpec,
    SlidingWindowSpec,
)

pytestmark = pytest.mark.cpu_test


def get_sliding_window_manager(sliding_window_spec, block_pool, enable_caching=True):
    # Tests don't exercise admission gating; pass a large cap that is a no-op.
    return SlidingWindowManager(
        sliding_window_spec,
        block_pool=block_pool,
        enable_caching=enable_caching,
        kv_cache_group_id=0,
        scheduler_block_size=sliding_window_spec.block_size,
        max_admission_blocks_per_request=10**9,
    )


def get_chunked_local_attention_manager(
    chunked_local_attention_spec, block_pool, enable_caching=True
):
    return ChunkedLocalAttentionManager(
        chunked_local_attention_spec,
        block_pool=block_pool,
        enable_caching=enable_caching,
        kv_cache_group_id=0,
        scheduler_block_size=chunked_local_attention_spec.block_size,
        max_admission_blocks_per_request=10**9,
    )


def test_chunked_local_attention_possible_cached_prefix():
    block_size = 2
    chunked_local_attention_spec = ChunkedLocalAttentionSpec(
        block_size=block_size,
        num_kv_heads=1,
        head_size=1,
        dtype=torch.float32,
        attention_chunk_size=4,
    )

    block_pool = BlockPool(
        num_gpu_blocks=100, enable_caching=True, hash_block_size=block_size
    )
    manager = get_chunked_local_attention_manager(
        chunked_local_attention_spec, block_pool
    )

    def run_one_case(block_is_cached, tail_token, expect_length):
        block_hash_list = [
            BlockHash(str(i).encode()) for i in range(len(block_is_cached))
        ]

        block_pool.cached_block_hash_to_block._cache.clear()

        # Mock the block pool with the cached blocks
        for i, (block_hash, is_cached) in enumerate(
            zip(block_hash_list, block_is_cached)
        ):
            if is_cached:
                block_pool.cached_block_hash_to_block.insert(
                    make_block_hash_with_group_id(block_hash, 0),
                    block_pool.blocks[i + 10],
                )

        computed_blocks = manager.find_longest_cache_hit(
            block_hashes=block_hash_list,
            max_length=len(block_hash_list) * block_size + tail_token,
            kv_cache_group_ids=[0],
            block_pool=block_pool,
            kv_cache_spec=chunked_local_attention_spec,
            drop_eagle_block=False,
            alignment_tokens=block_size,
        )[0][0]
        assert len(computed_blocks) == expect_length

        assert all(
            block == block_pool.null_block
            for block in computed_blocks[: (expect_length - 1) // 2]
        )

    run_one_case([True], 0, 1)
    run_one_case([True], 1, 1)
    run_one_case([True, False], 0, 2)
    run_one_case([True, False], 1, 2)
    run_one_case([True, True], 0, 2)
    run_one_case([True, True], 1, 2)
    run_one_case([True, True, False], 0, 2)
    run_one_case([True, True, False], 1, 2)
    run_one_case([True, True, True], 0, 3)
    run_one_case([True, True, True], 1, 3)
    run_one_case([True, True, True, False], 0, 4)
    run_one_case([True, True, True, False], 1, 4)
    run_one_case([random.choice([True, False])] * 8 + [True], 1, 9)
    run_one_case([random.choice([True, False])] * 8 + [False], 1, 8)
    run_one_case([random.choice([True, False])] * 8 + [True, True], 1, 10)
    run_one_case([random.choice([True, False])] * 8 + [True, False], 0, 10)
    run_one_case([random.choice([True, False])] * 8 + [True, False], 1, 10)
    run_one_case([random.choice([True, False])] * 8 + [False, True], 0, 10)
    run_one_case([random.choice([True, False])] * 8 + [False, True], 1, 10)
    run_one_case([random.choice([True, False])] * 8 + [False, False], 0, 10)
    run_one_case([random.choice([True, False])] * 8 + [False, False], 1, 10)


def test_sliding_window_possible_cached_prefix():
    block_size = 2
    sliding_window_spec = SlidingWindowSpec(
        block_size=block_size,
        num_kv_heads=1,
        head_size=1,
        dtype=torch.float32,
        sliding_window=4,
    )

    block_pool = BlockPool(
        num_gpu_blocks=100, enable_caching=True, hash_block_size=block_size
    )
    manager = get_sliding_window_manager(sliding_window_spec, block_pool)

    def run_one_case(block_is_cached, expect_length):
        block_hash_list = [
            BlockHash(str(i).encode()) for i in range(len(block_is_cached))
        ]

        block_pool.cached_block_hash_to_block._cache.clear()

        # Mock the block pool with the cached blocks
        for i, (block_hash, is_cached) in enumerate(
            zip(block_hash_list, block_is_cached)
        ):
            if is_cached:
                block_pool.cached_block_hash_to_block.insert(
                    make_block_hash_with_group_id(block_hash, 0),
                    block_pool.blocks[i + 10],
                )

        computed_blocks = manager.find_longest_cache_hit(
            block_hashes=block_hash_list,
            max_length=len(block_hash_list) * block_size,
            kv_cache_group_ids=[0],
            block_pool=block_pool,
            kv_cache_spec=sliding_window_spec,
            drop_eagle_block=False,
            alignment_tokens=block_size,
        )[0][0]
        assert len(computed_blocks) == expect_length

        assert all(
            block == block_pool.null_block
            for block in computed_blocks[: expect_length - 2]
        )
        for i in range(2):
            if i < expect_length:
                block_index = expect_length - i - 1
                assert computed_blocks[block_index].block_id == block_index + 10

    run_one_case([False] * 10, 0)
    run_one_case([True], 1)
    run_one_case([True, False], 1)
    run_one_case([True, True], 2)
    run_one_case([True, True, False], 2)
    run_one_case([True, True, True], 3)
    run_one_case([True, True, True, False], 3)
    run_one_case(
        [True, True, False, True, False, False, True, True, False, True, True, True], 12
    )
    run_one_case(
        [True, True, False, True, False, False, True, True, False, False, False], 8
    )
    run_one_case(
        [True, True, False, True, False, False, True, True, False, False, False, True],
        8,
    )


def test_chunked_local_attention_remove_skipped_blocks():
    attention_spec = ChunkedLocalAttentionSpec(
        block_size=2,
        num_kv_heads=1,
        head_size=1,
        dtype=torch.float32,
        attention_chunk_size=4,
    )

    block_pool = BlockPool(num_gpu_blocks=2000, enable_caching=True, hash_block_size=2)

    manager = get_chunked_local_attention_manager(attention_spec, block_pool)

    null_block_id = block_pool.null_block.block_id

    def id_to_block_table(ids) -> list[KVCacheBlock]:
        return [
            KVCacheBlock(id_) if id_ != null_block_id else block_pool.null_block
            for id_ in ids
        ]

    def assert_block_id(block_table: list[KVCacheBlock], ids: list[int]):
        for block, id_ in zip(block_table, ids):
            if id_ == null_block_id:
                assert block == block_pool.null_block
            else:
                assert block.block_id == id_

    original_block_ids = [
        1000,
        1001,
        1002,
        1003,
        1004,
        1005,
        1006,
        1007,
        1008,
        1009,
        1010,
    ]
    block_table = id_to_block_table(original_block_ids)
    manager.req_to_blocks["test"] = block_table

    manager.remove_skipped_blocks("test", 0)
    assert_block_id(block_table, original_block_ids)

    # For 4th token (0-indexed), token 0-3 is out of the local attention window.
    manager.remove_skipped_blocks("test", 4)
    assert_block_id(block_table, [null_block_id] * 2)

    # For 6th token (0-indexed), token 4 - 6 are in local attention window,
    # token 0 - 3 are out, 2 blocks can be removed.
    manager.remove_skipped_blocks("test", 6)
    assert_block_id(block_table, [null_block_id] * 2 + original_block_ids[2:])
    # For 12th token (0-indexed),
    # token 0-11 are out, 6 block can be removed.
    manager.remove_skipped_blocks("test", 12)
    assert_block_id(block_table, [null_block_id] * 6)


def test_sliding_window_remove_skipped_blocks():
    sliding_window_spec = SlidingWindowSpec(
        block_size=2,
        num_kv_heads=1,
        head_size=1,
        dtype=torch.float32,
        sliding_window=4,
    )

    block_pool = BlockPool(num_gpu_blocks=2000, enable_caching=True, hash_block_size=2)

    manager = get_sliding_window_manager(sliding_window_spec, block_pool)

    null_block_id = block_pool.null_block.block_id

    def id_to_block_table(ids) -> list[KVCacheBlock]:
        return [
            KVCacheBlock(id_) if id_ != null_block_id else block_pool.null_block
            for id_ in ids
        ]

    def assert_block_id(block_table: list[KVCacheBlock], ids: list[int]):
        for block, id_ in zip(block_table, ids):
            if id_ == null_block_id:
                assert block == block_pool.null_block
            else:
                assert block.block_id == id_

    original_block_ids = [
        1000,
        1001,
        1002,
        1003,
        1004,
        1005,
        1006,
        1007,
        1008,
        1009,
        1010,
    ]
    block_table = id_to_block_table(original_block_ids)
    manager.req_to_blocks["test"] = block_table

    manager.remove_skipped_blocks("test", 0)
    assert_block_id(block_table, original_block_ids)

    # 4 tokens are computed. Only token 0 is out of the sliding window. As
    # block 1000 also contains token 1 that is in the sliding window, block 1000
    # cannot be removed.
    manager.remove_skipped_blocks("test", 4)
    assert_block_id(block_table, original_block_ids)

    # 5 tokens are computed. Token 0 & 1 are out of the sliding window.
    # Block 1000 can be removed.
    manager.remove_skipped_blocks("test", 5)
    assert_block_id(block_table, [null_block_id] + original_block_ids[1:])

    # 6 tokens are computed. Token 0-2 are out of the sliding window.
    # Cannot remove new block as the block 1001 is still used by token 3.
    manager.remove_skipped_blocks("test", 6)
    assert_block_id(block_table, [null_block_id] + original_block_ids[1:])

    # 7 tokens are computed. Token 0-3 are out of the sliding window.
    # Block 1001 can be removed and block 1000 is already removed.
    manager.remove_skipped_blocks("test", 7)
    assert_block_id(block_table, [null_block_id] * 2 + original_block_ids[2:])

    # 11 tokens are computed. Token 0-7 are out of the sliding window.
    # Block 1002 & 1003 can be removed now. Block 1003 represents a longer
    # sequence, and is expected to be evicted earlier than 1002, so the order
    # of removed blocks should be [1003, 1002].
    manager.remove_skipped_blocks("test", 11)
    assert_block_id(block_table, [null_block_id] * 4 + original_block_ids[4:])


def test_rswa_remove_skipped_blocks_gap_range():
    block_size = 4
    rswa_spec = RSWASpec(
        block_size=block_size,
        num_kv_heads=1,
        head_size=1,
        dtype=torch.float32,
        rswa_window=8,
    )
    block_pool = BlockPool(num_gpu_blocks=2000, enable_caching=True, hash_block_size=4)
    manager = RSWAManager(
        rswa_spec,
        block_pool=block_pool,
        enable_caching=True,
        kv_cache_group_id=0,
        scheduler_block_size=block_size,
    )

    null_block_id = block_pool.null_block.block_id
    original_block_ids = list(range(1000, 1010))
    block_table = [
        KVCacheBlock(id_) if id_ != null_block_id else block_pool.null_block
        for id_ in original_block_ids
    ]
    manager.req_to_blocks["test"] = block_table

    prefix_len = 16

    # Without num_prompt_tokens, R-SWA does not evict gap blocks.
    manager.remove_skipped_blocks("test", 28)
    assert [b.block_id for b in block_table] == original_block_ids

    # Gap = block 4 only (tokens [16, 20) fall in the gap).
    manager.remove_skipped_blocks("test", 28, num_prompt_tokens=prefix_len)
    expected = original_block_ids.copy()
    expected[4] = null_block_id
    assert [b.block_id for b in block_table] == expected

    # Window moves: blocks 5 and 6 also enter the gap; block 4 is already null.
    manager.remove_skipped_blocks("test", 36, num_prompt_tokens=prefix_len)
    expected[5] = null_block_id
    expected[6] = null_block_id
    assert [b.block_id for b in block_table] == expected


def test_get_num_blocks_to_allocate():
    block_size = 2
    sliding_window_spec = SlidingWindowSpec(
        block_size=block_size,
        num_kv_heads=1,
        head_size=1,
        dtype=torch.float32,
        sliding_window=4,  # Placeholder value, not related to test result
    )

    block_pool = BlockPool(
        num_gpu_blocks=100, enable_caching=True, hash_block_size=block_size
    )
    manager = get_sliding_window_manager(sliding_window_spec, block_pool)
    cached_blocks_1 = [KVCacheBlock(i + 1) for i in range(10)]
    cached_blocks_2 = [block_pool.null_block for _ in range(5)] + [
        KVCacheBlock(i + 1) for i in range(5)
    ]

    assert (
        manager.get_num_blocks_to_allocate(
            "1", 20 * block_size, cached_blocks_1, 0, 0, 20 * block_size
        )
        == 20
    )
    assert (
        manager.get_num_blocks_to_allocate(
            "2", 20 * block_size, cached_blocks_2, 0, 0, 20 * block_size
        )
        == 15
    )


def test_evictable_cached_blocks_not_double_allocated():
    block_size = 2
    sliding_window_length = 2 * block_size
    sliding_window_spec = SlidingWindowSpec(
        block_size=block_size,
        num_kv_heads=1,
        head_size=1,
        dtype=torch.float32,
        sliding_window=sliding_window_length,
    )

    block_pool = BlockPool(
        num_gpu_blocks=100, enable_caching=True, hash_block_size=block_size
    )
    manager = get_sliding_window_manager(sliding_window_spec, block_pool)

    request_id = "req"
    evictable_block = block_pool.blocks[1]  # ref_cnt == 0, eviction candidate

    num_blocks_to_allocate = manager.get_num_blocks_to_allocate(
        request_id=request_id,
        num_tokens=2 * block_size,
        new_computed_blocks=[evictable_block],
        total_computed_tokens=block_size,
        num_local_computed_tokens=block_size,
        num_tokens_main_model=2 * block_size,
    )
    # Free capacity check should count evictable cached blocks, but allocation
    # should only allocate the truly new block.
    assert num_blocks_to_allocate == 2

    manager.add_local_computed_blocks(
        request_id,
        [evictable_block],
        num_local_computed_tokens=block_size,
        num_external_computed_tokens=0,
    )
    new_blocks = manager.allocate_new_blocks(
        request_id, num_tokens=4, num_tokens_main_model=4
    )
    assert len(new_blocks) == 1
    assert len(manager.req_to_blocks[request_id]) == 2


def test_chunked_local_attention_get_num_blocks_to_allocate():
    block_size = 2
    attention_spec = ChunkedLocalAttentionSpec(
        block_size=block_size,
        num_kv_heads=1,
        head_size=1,
        dtype=torch.float32,
        attention_chunk_size=4,  # Placeholder value, not related to test result
    )

    block_pool = BlockPool(
        num_gpu_blocks=100, enable_caching=True, hash_block_size=block_size
    )
    manager = get_chunked_local_attention_manager(attention_spec, block_pool)
    cached_blocks_1 = [KVCacheBlock(i + 1) for i in range(10)]
    cached_blocks_2 = [block_pool.null_block for _ in range(5)] + [
        KVCacheBlock(i + 1) for i in range(5)
    ]

    assert (
        manager.get_num_blocks_to_allocate(
            "1", 20 * block_size, cached_blocks_1, 0, 0, 20 * block_size
        )
        == 20
    )
    assert (
        manager.get_num_blocks_to_allocate(
            "2", 20 * block_size, cached_blocks_2, 0, 0, 20 * block_size
        )
        == 15
    )


def test_predictor_matches_allocator_blocks_calculation_with_admission_cap():
    """In forward steps, `get_num_blocks_to_allocate` must return exactly what
    `allocate_new_blocks` will pull; otherwise `block_pool.get_new_blocks`
    raises `ValueError: Cannot get N free blocks from the pool`.
    """
    block_size = 2
    sliding_window = 8  # 4-block live window
    cap = sliding_window // block_size

    spec = SlidingWindowSpec(
        block_size=block_size,
        num_kv_heads=1,
        head_size=1,
        dtype=torch.float32,
        sliding_window=sliding_window,
    )
    block_pool = BlockPool(
        num_gpu_blocks=100, enable_caching=True, hash_block_size=block_size
    )
    manager = SlidingWindowManager(
        spec,
        block_pool=block_pool,
        enable_caching=False,
        kv_cache_group_id=0,
        scheduler_block_size=spec.block_size,
        max_admission_blocks_per_request=cap,
    )

    request_id = "req"
    total_computed = 0
    # Walk through request forward steps. Check num_blocks returned by
    # `get_num_blocks_to_allocate` matches what `allocate_new_blocks` pulls
    for num_tokens in (4, 8, 12, 16):
        predicted = manager.get_num_blocks_to_allocate(
            request_id=request_id,
            num_tokens=num_tokens,
            new_computed_blocks=[],
            total_computed_tokens=total_computed,
            num_local_computed_tokens=0,
            num_tokens_main_model=num_tokens,
        )
        new_blocks = manager.allocate_new_blocks(
            request_id, num_tokens=num_tokens, num_tokens_main_model=num_tokens
        )
        assert predicted == len(new_blocks), (
            f"num_tokens={num_tokens}: predictor returned {predicted} "
            f"but allocator pulled {len(new_blocks)}"
        )
        total_computed = num_tokens


def _make_align_mamba_manager(large_block_factor: int = 4, block_size: int = 16):
    """MambaManager in align mode on a hierarchical (large-block) pool."""
    from vllm.v1.core.single_type_kv_cache_manager import MambaManager
    from vllm.v1.kv_cache_interface import MambaSpec

    spec = MambaSpec(
        block_size=block_size,
        shapes=(1, 1),
        dtypes=(torch.float32,),
        mamba_cache_mode="align",
        large_block_factor=large_block_factor,
    )
    block_pool = BlockPool(
        num_gpu_blocks=32,
        enable_caching=True,
        hash_block_size=block_size,
        large_block_factor=large_block_factor,
    )
    manager = MambaManager(
        spec,
        block_pool,
        enable_caching=True,
        kv_cache_group_id=0,
        scheduler_block_size=block_size,
    )
    return manager, block_pool


def test_mamba_align_admission_counts_in_small_units():
    """The coordinator sums per-manager block counts against the pool's
    SMALL-unit free count, so a large-block mamba manager must report its
    align-mode requirement scaled by large_block_factor."""

    def count(factor: int) -> int:
        manager, _ = _make_align_mamba_manager(large_block_factor=factor, block_size=16)
        return manager.get_num_blocks_to_allocate(
            request_id="r0",
            num_tokens=32,
            new_computed_blocks=[],
            total_computed_tokens=0,
            num_local_computed_tokens=0,
            num_tokens_main_model=32,
        )

    # The invariant: a hierarchical manager reports exactly the flat-mode
    # count scaled to small units.
    flat = count(1)
    assert flat >= 1
    assert count(4) == flat * 4


def test_mamba_align_state_block_is_large():
    """Align allocates one real state block per step; on a hierarchical pool
    that block must come from the large-block queue (a full state slot),
    with the skipped positions padded by nulls."""
    manager, pool = _make_align_mamba_manager(large_block_factor=4, block_size=16)
    free_large_before = pool.get_num_free_large_blocks()
    new_blocks = manager.allocate_new_blocks(
        request_id="r0", num_tokens=32, num_tokens_main_model=32
    )
    req_blocks = manager.req_to_blocks["r0"]
    real_blocks = [b for b in req_blocks if not b.is_null]
    assert len(real_blocks) == 1
    state_block = real_blocks[0]
    # Identity check: the allocated block IS its meta's large block.
    meta = pool.large_block_metas[state_block.block_id]
    assert meta.large_block is state_block
    assert pool.get_num_free_large_blocks() == free_large_before - 1
    assert state_block in new_blocks


def test_mamba_align_partial_hit_cow_block_is_large():
    """A partial prefix-cache hit redirects the shared tail state to a private
    CoW block; on a hierarchical pool the CoW destination must be a LARGE
    block (it holds one full state), and the pending copy pair must be
    recorded for the worker."""
    manager, pool = _make_align_mamba_manager(large_block_factor=4, block_size=16)
    # Seed a request that "hit" one cached state block.
    source_block = pool.get_new_blocks(1, large_block=True)[0]
    manager.req_to_blocks["r0"].append(source_block)
    manager._partial_hit_reqs["r0"] = (0, source_block)

    manager.allocate_new_blocks(
        request_id="r0", num_tokens=32, num_tokens_main_model=32
    )

    req_blocks = manager.req_to_blocks["r0"]
    # The source was displaced by the CoW copy.
    assert source_block not in req_blocks
    cow_block = req_blocks[0]
    meta = pool.large_block_metas[cow_block.block_id]
    assert meta.large_block is cow_block
    assert (source_block, cow_block) in manager._pending_cow_copies
    # Both endpoints stay retained until the worker-side copy has run.
    assert source_block.ref_cnt >= 1
    assert cow_block.ref_cnt >= 2


def test_mamba_align_external_allocation_shape():
    """A connector (external) hit must produce the same align block layout as
    a local GPU hit: null padding plus a SINGLE real state block at the last
    computed index. The base-class path allocates one real block per
    allocation-block span instead, wasting large blocks and populating the
    worker block table with garbage-filled state slots."""
    manager, pool = _make_align_mamba_manager(large_block_factor=4, block_size=16)
    free_large_before = pool.get_num_free_large_blocks()

    # Connector-style resume: no local hit, 320 external (loaded) tokens.
    manager.add_local_computed_blocks(
        request_id="r0",
        new_computed_blocks=[],
        num_local_computed_tokens=0,
        num_external_computed_tokens=320,
    )
    manager.allocate_external_computed_blocks(
        request_id="r0",
        num_local_computed_tokens=0,
        num_external_computed_tokens=320,
    )

    req_blocks = manager.req_to_blocks["r0"]
    assert len(req_blocks) == 320 // 16
    real_blocks = [b for b in req_blocks if not b.is_null]
    # Align semantics: exactly ONE state slot holds the loaded state, at the
    # last computed index (the align convention consumed by the worker).
    assert len(real_blocks) == 1, f"expected 1 real state block, got {len(real_blocks)}"
    assert req_blocks[-1] is real_blocks[0]
    assert pool.get_num_free_large_blocks() == free_large_before - 1


def _make_hierarchical_attention_manager(large_block_factor: int = 4):
    """FullAttentionManager on a hierarchical (large-block) pool."""
    from vllm.v1.core.single_type_kv_cache_manager import FullAttentionManager
    from vllm.v1.kv_cache_interface import FullAttentionSpec

    block_size = 16
    spec = FullAttentionSpec(
        block_size=block_size,
        num_kv_heads=1,
        head_size=1,
        dtype=torch.float32,
    )
    pool = BlockPool(
        num_gpu_blocks=32,
        enable_caching=True,
        hash_block_size=block_size,
        large_block_factor=large_block_factor,
    )
    manager = FullAttentionManager(
        spec,
        block_pool=pool,
        enable_caching=True,
        kv_cache_group_id=0,
        scheduler_block_size=block_size,
        max_admission_blocks_per_request=10**9,
    )
    return manager, pool


def _recycled_meta_with_cached_hits(pool, num_hits=2):
    """Cache `num_hits` small blocks, free them so their meta recycles into
    the free-large queue, then occupy the rest of the pool down to exactly
    2 free large blocks. Returns the evictable hit blocks."""
    from vllm.v1.core.kv_cache_utils import (
        BlockHash,
        make_block_hash_with_group_id,
    )

    n = pool.large_block_factor
    smalls = pool.get_new_blocks(num_hits)
    meta = pool.large_block_metas[smalls[0].block_id // n]
    for i, blk in enumerate(smalls):
        key = make_block_hash_with_group_id(BlockHash(f"prefix-{i}".encode()), 0)
        blk.set_block_hash(key, num_tokens=None)
        pool.cached_block_hash_to_block.insert(key, blk)
    pool.free_blocks(smalls)  # meta recycled; hashes linger -> evictable hits

    held = []
    while pool.get_num_free_large_blocks() > 2:
        blk = pool.get_new_blocks(1, large_block=True)[0]
        if blk is meta.large_block:
            pool.free_blocks([blk], large_block=True)
            held.extend(pool.get_new_blocks(2, large_block=True))
        else:
            held.append(blk)
    return smalls


def test_hierarchical_admission_counts_touch_cost_of_recycled_meta():
    """Regression: touching an evictable hit whose parent meta is RECYCLED
    removes a whole large block (factor small units) from the free ledger,
    but admission used to count it as 1 small unit — the scheduler admitted
    requests get_new_blocks could not serve, crashing the engine with an
    uncaught ValueError under ordinary near-full prefix-caching load."""
    n = 4
    manager, pool = _make_hierarchical_attention_manager(large_block_factor=n)
    block_size = manager.block_size
    smalls = _recycled_meta_with_cached_hits(pool, num_hits=2)

    free_small = pool.get_num_free_blocks()
    assert free_small == 2 * n  # 2 free large blocks

    # 7 total blocks: 2 evictable cached hits + 5 new. The touch of the
    # recycled meta costs n=4 small units, so the true need is 5 + 4 = 9 > 8:
    # admission must refuse (the old per-block count said 5 + 2 = 7 <= 8).
    need = manager.get_num_blocks_to_allocate(
        request_id="r-refuse",
        num_tokens=7 * block_size,
        new_computed_blocks=smalls,
        total_computed_tokens=2 * block_size,
        num_local_computed_tokens=2 * block_size,
        num_tokens_main_model=7 * block_size,
    )
    assert need == 5 + n
    assert need > free_small

    # 6 total blocks: 4 new + touch cost 4 = 8 <= 8: admitted, and the
    # allocator must then actually serve it without raising.
    need = manager.get_num_blocks_to_allocate(
        request_id="r-admit",
        num_tokens=6 * block_size,
        new_computed_blocks=smalls,
        total_computed_tokens=2 * block_size,
        num_local_computed_tokens=2 * block_size,
        num_tokens_main_model=6 * block_size,
    )
    assert need == 4 + n
    assert need <= free_small
    pool.touch(smalls)
    new_blocks = pool.get_new_blocks(4, last_hit_block_id=smalls[-1].block_id)
    assert len(new_blocks) == 4


def test_hierarchical_admission_hits_in_partial_meta_cost_nothing():
    """Evictable hits inside a PARTIAL meta (other smalls still in use)
    do not move the free ledger when touched; admission must not charge
    for them."""
    from vllm.v1.core.kv_cache_utils import (
        BlockHash,
        make_block_hash_with_group_id,
    )

    n = 4
    manager, pool = _make_hierarchical_attention_manager(large_block_factor=n)
    block_size = manager.block_size

    # 3 smalls from one meta; cache and free two, keep the third in use so
    # the meta stays partial (never recycles).
    smalls = pool.get_new_blocks(3)
    for i, blk in enumerate(smalls[:2]):
        key = make_block_hash_with_group_id(BlockHash(f"p-{i}".encode()), 0)
        blk.set_block_hash(key, num_tokens=None)
        pool.cached_block_hash_to_block.insert(key, blk)
    pool.free_blocks(smalls[:2])

    free_before = pool.get_num_free_blocks()
    need = manager.get_num_blocks_to_allocate(
        request_id="r",
        num_tokens=3 * block_size,
        new_computed_blocks=smalls[:2],
        total_computed_tokens=2 * block_size,
        num_local_computed_tokens=2 * block_size,
        num_tokens_main_model=3 * block_size,
    )
    assert need == 1  # 1 new block; the partial-meta hits cost 0
    pool.touch(smalls[:2])
    assert pool.get_num_free_blocks() == free_before  # ledger unmoved

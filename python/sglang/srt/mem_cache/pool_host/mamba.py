from __future__ import annotations

import logging
import threading
from typing import Optional, Sequence

import numpy as np
import torch

from sglang.srt.mem_cache.device_pool_info import MambaStateBufferInfo
from sglang.srt.mem_cache.pool_host._kvcacheio import require_kvcacheio_ops
from sglang.srt.mem_cache.pool_host.base import (
    HostKVCache,
    host_memory_preflight,
    sync_fixed_hicache_size,
    synchronized,
)
from sglang.srt.mem_cache.pool_host.common import (
    ALLOC_MEMORY_FUNCS,
    get_allocator_from_storage,
)
from sglang.srt.utils import is_cuda, is_hip, is_npu, is_xpu

_is_cuda = is_cuda()
_is_hip = is_hip()
_is_npu = is_npu()
_is_xpu = is_xpu()
# XPU ops only when no CUDA/ROCm backend is present, matching the imports below.
_use_xpu_mamba_ops = _is_xpu and not (_is_cuda or _is_hip)
if _is_cuda or _is_hip:
    from sgl_kernel.kvcacheio import (
        transfer_kv_all_layer_direct_lf_pf,
        transfer_kv_per_layer_direct_pf_lf,
    )

    from sglang.kernels.ops.mamba.transfer_mamba import (
        transfer_kv_mamba_lf_pf,
        transfer_kv_mamba_pf_lf,
    )
elif _is_xpu:
    from sglang.srt.mem_cache.pool_host._kvcacheio import (
        transfer_kv_all_layer_direct_lf_pf,
        transfer_kv_mamba_lf_pf,
        transfer_kv_mamba_pf_lf,
        transfer_kv_per_layer_direct_pf_lf,
    )
if _is_npu:
    from sgl_kernel_npu.operators.mem_cache.memfabric.kv_transfer import (
        transfer_kv_all_layer_kv_split_lf_pf,
        transfer_kv_per_layer_kv_split_pf_lf,
    )

logger = logging.getLogger(__name__)


# Caps the XPU slot-stacking buffer at ~1% of a 24 GB Arc Pro B60, inside the
# device headroom mem-fraction-static leaves; arbitrary, not measured.
_XPU_STACK_CHUNK_BYTES = 256 << 20


class MambaPoolHost(HostKVCache):
    mtp_draft_buffer_infos: tuple[MambaStateBufferInfo, ...] = ()

    if _is_xpu:
        # {io_backend: {layout: kvcacheio ops}} the transfer methods below call,
        # checked at construction; keep in step with their branches.
        _kvcacheio_ops = {
            "kernel": {
                "page_first": ("transfer_kv_mamba_pf_lf", "transfer_kv_mamba_lf_pf"),
            },
            "direct": {
                "page_first_direct": (
                    "transfer_kv_per_layer_direct_pf_lf",
                    "transfer_kv_all_layer_direct_lf_pf",
                ),
            },
        }

    # Class-level defaults so a model without side state, and the test stubs that
    # skip __init__, still read an empty pair rather than raising.
    slot_state_device_tensors: tuple = ()
    slot_state_buffers: tuple = ()
    _kv_split_views: tuple = ()

    def __init__(
        self,
        buffer_info: MambaStateBufferInfo,
        host_to_device_ratio: float,
        host_size: int,
        *,
        device_capacity: int,
        pin_memory: bool = True,
        device: str = "cpu",
        allocator_type: str = "default",
        layout: str = "layer_first",
        mtp_draft_buffer_infos: Sequence[MambaStateBufferInfo] = (),
    ):
        buffer_info.validate()
        self.buffer_info = buffer_info
        self.device_pool = None
        self._buffer_device = buffer_info.temporal.device
        self.mtp_draft_buffer_infos = tuple(mtp_draft_buffer_infos)
        self.page_size = 1

        assert layout in [
            "page_first",
            "page_first_direct",
        ], f"Unsupported layout: {layout}"
        if _is_xpu:
            require_kvcacheio_ops(
                pool=type(self).__name__, layout=layout, ops=self._kvcacheio_ops
            )

        self.layout = layout
        self.pin_memory = pin_memory
        self.device = device
        self.allocator = get_allocator_from_storage(allocator_type)
        self.num_mamba_layers = buffer_info.temporal.shape[0] + len(
            self.mtp_draft_buffer_infos
        )

        buffer_infos = (buffer_info, *self.mtp_draft_buffer_infos)
        for draft_info in self.mtp_draft_buffer_infos:
            draft_info.validate()
            assert draft_info.temporal.shape[0] == 1
            assert len(draft_info.conv) == len(buffer_info.conv)
            for target, draft in zip(
                (*buffer_info.conv, buffer_info.temporal),
                (*draft_info.conv, draft_info.temporal),
                strict=True,
            ):
                assert target.shape[1:] == draft.shape[1:]
                assert target.dtype == draft.dtype
                assert target.device == draft.device

        self.temporal_device_layers = [
            layer for info in buffer_infos for layer in info.temporal.unbind(0)
        ]
        self.conv_device_layers = [
            [layer for info in buffer_infos for layer in info.conv[i].unbind(0)]
            for i in range(len(buffer_info.conv))
        ]

        self.conv_state_shapes = [
            conv_state.shape[2:] for conv_state in self.buffer_info.conv
        ]
        self.temporal_state_shape = self.buffer_info.temporal.shape[2:]
        self.temporal_state_elem_size = int(np.prod(self.temporal_state_shape))
        self.conv_state_elem_sizes = [
            int(np.prod(conv_shape)) for conv_shape in self.conv_state_shapes
        ]
        self.conv_dtype = self.buffer_info.conv[0].dtype
        self.temporal_dtype = self.buffer_info.temporal.dtype
        self.dtype = self.conv_dtype
        # Registered side states share the checkpoint slot with conv/temporal,
        # so a host round trip that skips them leaves the previous occupant's rows.
        self.slot_state_device_tensors = [
            buf for info in buffer_infos for buf in info.extra_checkpoint_buffers
        ]
        self.slot_state_buffers = []
        self.size_per_token = self.get_size_per_token()

        if host_size > 0:
            self.size = sync_fixed_hicache_size(
                int(host_size * 1e9 // self.size_per_token), host_size
            )
        else:
            self.size = int(device_capacity * host_to_device_ratio)

        self.page_num = self.size // self.page_size + 1
        self.size = self.page_num * self.page_size

        if self.size <= device_capacity:
            logger.warning(
                "HiCache host KV pool (%d tokens) is smaller than the device pool (%d tokens);"
                "L2 cache effectiveness is reduced."
                "Consider increasing --hicache-ratio (or --hicache-size) for higher L2 cache hit rate.",
                self.size,
                device_capacity,
            )

        allocation_bytes, available_bytes = host_memory_preflight(
            self.get_mapping_lengths(),
            self.allocator,
            self._buffer_device,
        )
        if allocation_bytes > available_bytes:
            raise ValueError(
                f"Not enough host memory available. Requesting "
                f"{allocation_bytes / 1e9:.2f} GB but only have "
                f"{available_bytes / 1e9:.2f} GB free. Please reduce the "
                f"size of the hierarchical cache."
            )
        logger.info(
            "Allocating %.2f GB host memory for hierarchical Mamba cache (%d state slots, layout=%s).",
            allocation_bytes / 1e9,
            self.size,
            self.layout,
        )

        self.temporal_device_ptrs = torch.tensor(
            [layer.data_ptr() for layer in self.temporal_device_layers],
            dtype=torch.uint64,
            device=self._buffer_device,
        )
        self.conv_device_ptrs = [
            torch.tensor(
                [layer.data_ptr() for layer in layers],
                dtype=torch.uint64,
                device=self._buffer_device,
            )
            for layers in self.conv_device_layers
        ]

        self.kv_buffer = self.init_kv_buffer()
        self._init_npu_kv_split_transfer()
        self._init_write_back_staging_buffers()
        self.lock = threading.RLock()
        self.clear()

    @staticmethod
    def _kv_split_view5(tensor):
        """Collapse [A, B, *S] to [A, P, 1, 1, W] as a pure view, or None
        when the trailing dims are not mergeable. `view` never copies, unlike
        `reshape`, which could silently duplicate the whole buffer."""
        try:
            return tensor.view(tensor.shape[0], tensor.shape[1], 1, 1, -1)
        except RuntimeError:
            return None

    def _init_npu_kv_split_transfer(self) -> None:
        """Pre-build the per-component views the kernel_ascend path submits.

        The split-KV operators require SGLANG_HICACHE_HOST_MEM_BACKEND=acl or
        memfabric; anything else is a configuration error. Missing operators
        already failed at import time.
        """
        self._kv_split_views = ()
        if not _is_npu:
            return

        # Device [L, P, 1, 1, W] / host [P, L, 1, 1, W] with page_size = 1:
        # one slot per page, trailing state shape collapsed to width W.
        views = []

        def add(name, key, dev, host):
            if dev is None or host is None:
                raise RuntimeError(
                    f"NPU kernel_ascend Mamba transfers cannot address "
                    f"component {name!r} in place: its per-slot payload is "
                    f"not contiguous."
                )
            views.append((name, key, dev, host))

        if self.temporal_state_elem_size > 0:
            add(
                "temporal",
                None,
                self._kv_split_view5(self.buffer_info.temporal),
                self._kv_split_view5(self.temporal_buffer),
            )
        for i in range(len(self.conv_state_shapes)):
            add(
                f"conv_{i}",
                None,
                self._kv_split_view5(self.buffer_info.conv[i]),
                self._kv_split_view5(self.conv_buffer[i]),
            )
        # Draft layers: separate single-layer device allocations targeting the
        # draft layer range of the shared host pool.
        n_main = self.buffer_info.temporal.shape[0]
        temporal_host_v = self._kv_split_view5(self.temporal_buffer)
        conv_host_vs = [self._kv_split_view5(buf) for buf in self.conv_buffer]
        for depth, draft_info in enumerate(self.mtp_draft_buffer_infos):
            host_layer = n_main + depth
            if draft_info.temporal.numel():
                add(
                    "temporal_draft",
                    depth,
                    self._kv_split_view5(draft_info.temporal),
                    temporal_host_v.narrow(1, host_layer, 1),
                )
            for i in range(len(self.conv_state_shapes)):
                if draft_info.conv[i].numel():
                    add(
                        f"conv_{i}_draft",
                        depth,
                        self._kv_split_view5(draft_info.conv[i]),
                        conv_host_vs[i].narrow(1, host_layer, 1),
                    )
        # Side states: no layer axis, so a single-layer component covers them.
        # unsqueeze is a pure view op, so the payload checks stay meaningful.
        for i, (state, buf) in enumerate(
            zip(self.slot_state_device_tensors, self.slot_state_buffers)
        ):
            if not state.numel() or not buf.numel():
                continue
            add(
                f"side_{i}",
                None,
                self._kv_split_view5(state.unsqueeze(0)),
                self._kv_split_view5(buf.unsqueeze(1)),
            )

        self._kv_split_views = tuple(views)
        logger.info(
            "NPU HiCache Mamba state transfer mode: kv_split (%d components).",
            len(views),
        )

    def _kv_split_indices(self, host_indices, device_indices):
        di = device_indices.reshape(-1).to(
            dtype=torch.int64, device=self._buffer_device
        )
        hi = host_indices.reshape(-1).to(
            dtype=torch.int64, device=self._buffer_device
        )
        return di, hi

    def _load_to_device_kv_split(self, host_indices, device_indices, layer_id) -> None:
        """H2D via the split-KV operator, one submission per component.

        The per-layer call covers one layer of every main component plus, on
        layer 0, the side states; draft layers ride their own single-layer
        component on the matching pool layer id.
        """
        di, hi = self._kv_split_indices(host_indices, device_indices)
        if di.numel() == 0:
            return
        n_main = self.buffer_info.temporal.shape[0]
        empty_dev = torch.empty(0, device=self._buffer_device)
        empty_host = torch.empty(0)
        for name, key, dev, host in self._kv_split_views:
            if name.endswith("_draft"):
                # Draft components submit once, on their own layer call. Their
                # host view is pre-narrowed to that single layer, so the layer
                # offset is already folded into the view and both operands
                # address layer 0.
                if layer_id != n_main + key:
                    continue
                device_layer_id = host_layer_id = 0
            else:
                if name.startswith("side_"):
                    if layer_id != 0:
                        continue
                    device_layer_id, host_layer_id = 0, 0
                elif layer_id >= n_main:
                    continue
                else:
                    device_layer_id = host_layer_id = layer_id
            transfer_kv_per_layer_kv_split_pf_lf(
                device_indices=di,
                host_indices=hi,
                device_k=dev,
                host_k=host,
                device_v=empty_dev,
                host_v=empty_host,
                page_size=1,
                device_layer_id=device_layer_id,
                host_layer_id=host_layer_id,
            )

    def _backup_from_device_kv_split(self, host_indices, device_indices) -> None:
        """D2H via the split-KV operator: every component in one all-layer call."""
        di, hi = self._kv_split_indices(host_indices, device_indices)
        if di.numel() == 0:
            return
        empty_dev = torch.empty(0, device=self._buffer_device)
        empty_host = torch.empty(0)
        for _, _, dev, host in self._kv_split_views:
            # Main views keep the full layer axis and fill host layers from 0;
            # draft/side host views are pre-narrowed to one layer, so they too
            # start at host layer 0.
            transfer_kv_all_layer_kv_split_lf_pf(
                device_indices=di,
                host_indices=hi,
                device_k=dev,
                host_k=host,
                device_v=empty_dev,
                host_v=empty_host,
                page_size=1,
                host_layer_start=0,
            )

    def init_kv_buffer(self):
        _host_alloc = ALLOC_MEMORY_FUNCS[self._buffer_device.type]

        def alloc_func(dims, *, dtype, device, pin_memory, allocator):
            # conv-only linear attention has no ssm state: mmap can't map the
            # 0-element temporal buffer, so hand back a plain empty tensor.
            if np.prod(dims) == 0:
                return torch.empty(dims, dtype=dtype, device=device)
            return _host_alloc(
                dims,
                dtype=dtype,
                device=device,
                pin_memory=pin_memory,
                allocator=allocator,
                registration_granularity_bytes=(
                    int(np.prod(dims[1:])) * dtype.itemsize
                ),
            )

        if self.layout in ["page_first", "page_first_direct"]:
            # page-first: (page_num, num_layers, 1, *shape) — per-page data is contiguous
            temporal_dims = (
                self.size,
                self.num_mamba_layers,
                1,
            ) + self.temporal_state_shape
            self.temporal_buffer = alloc_func(
                temporal_dims,
                dtype=self.temporal_dtype,
                device=self.device,
                pin_memory=self.pin_memory,
                allocator=self.allocator,
            )
            self.conv_buffer = []
            for conv_shape in self.conv_state_shapes:
                conv_dims = (self.size, self.num_mamba_layers, 1) + conv_shape
                self.conv_buffer.append(
                    alloc_func(
                        conv_dims,
                        dtype=self.conv_dtype,
                        device=self.device,
                        pin_memory=self.pin_memory,
                        allocator=self.allocator,
                    )
                )
        else:
            # layer-first: (num_layers, size, *shape)
            temporal_dims = (
                self.num_mamba_layers,
                self.size,
            ) + self.temporal_state_shape
            self.temporal_buffer = alloc_func(
                temporal_dims,
                dtype=self.temporal_dtype,
                device=self.device,
                pin_memory=self.pin_memory,
                allocator=self.allocator,
            )
            self.conv_buffer = []
            for conv_shape in self.conv_state_shapes:
                conv_dims = (self.num_mamba_layers, self.size) + conv_shape
                self.conv_buffer.append(
                    alloc_func(
                        conv_dims,
                        dtype=self.conv_dtype,
                        device=self.device,
                        pin_memory=self.pin_memory,
                        allocator=self.allocator,
                    )
                )
        # Side state keeps its own dtype and its own slot axis (axis 0 of the
        # per-layer view the device pool yields).
        self.slot_state_buffers = [
            alloc_func(
                (self.size,) + tuple(state.shape[1:]),
                dtype=state.dtype,
                device=self.device,
                pin_memory=self.pin_memory,
                allocator=self.allocator,
            )
            for state in self.slot_state_device_tensors
        ]
        # destroy() unregisters via kv_buffer; without this list the pinned
        # registrations leak past the buffers' mmap. 0-element buffers
        # (conv-only models' temporal state) were never registered.
        return [
            buf
            for buf in (
                self.temporal_buffer,
                *self.conv_buffer,
                *self.slot_state_buffers,
            )
            if buf.numel() > 0
        ]

    def _init_write_back_staging_buffers(self):
        self.temporal_staging_buffer = None
        self.conv_staging_buffers = [None] * len(self.conv_buffer)
        # Must be True: HostPoolGroup computes can_use_write_back_jit as AND of
        # all pools. When True, start_writing() keeps indices on CPU, which MLA's
        # staged write-back kernel requires. MambaPoolHost's own backup path does
        # not check this flag — it routes by layout + io_backend instead.
        self.can_use_write_back_jit = True
        self._temporal_can_use_jit = False
        self._conv_can_use_jit = [False] * len(self.conv_buffer)

    def get_hybrid_pool_buffer(self):
        # Expose all mamba host tensors that need Mooncake buffer registration.
        return [self.temporal_buffer, *self.conv_buffer, *self.slot_state_buffers]

    def _iter_page_tensors(self, index: int):
        if self.layout in ["page_first", "page_first_direct"]:
            yield self.temporal_buffer[index]
            for conv_buf in self.conv_buffer:
                yield conv_buf[index]
        else:
            yield self.temporal_buffer[:, index : index + self.page_size]
            for conv_buf in self.conv_buffer:
                yield conv_buf[:, index : index + self.page_size]
        for state_buf in self.slot_state_buffers:
            yield state_buf[index : index + self.page_size]

    @staticmethod
    def _flatten_tensor_bytes(tensor: torch.Tensor) -> torch.Tensor:
        return tensor.contiguous().view(torch.uint8).reshape(-1)

    @synchronized
    def clear(self):
        self.mem_state = torch.zeros(
            (self.size,), dtype=torch.uint8, device=self.device
        )
        self.free_slots = torch.arange(self.size, dtype=torch.int64)
        self.release_slots = []
        self.num_release_slots = 0

    def available_size(self):
        return len(self.free_slots) + self.num_release_slots

    @synchronized
    def alloc(self, need_size: int) -> Optional[torch.Tensor]:
        assert need_size % self.page_size == 0, (
            "The requested size should be a multiple of the page size."
        )
        if need_size > self.available_size():
            return None

        if need_size > len(self.free_slots):
            self._merge_release_slots()

        select_index = self.free_slots[:need_size]
        self.free_slots = self.free_slots[need_size:]
        return select_index

    @synchronized
    def free(self, indices: torch.Tensor) -> int:
        indices_cpu = indices.cpu()
        if indices_cpu.numel() == 0:
            return 0

        self.release_slots.append(indices_cpu)
        self.num_release_slots += len(indices_cpu)
        return len(indices)

    def get_size_per_token(self):
        conv_total_size = sum(
            conv_elem_size * self.conv_dtype.itemsize
            for conv_elem_size in self.conv_state_elem_sizes
        )
        temporal_size = self.temporal_state_elem_size * self.temporal_dtype.itemsize
        # Side-state rows are per-slot, not per-layer: each entry is already a
        # single layer's view, so its own row size is added once.
        side_size = sum(
            state[0].numel() * state.element_size()
            for state in self.slot_state_device_tensors
        )
        return (conv_total_size + temporal_size) * self.num_mamba_layers + side_size

    def get_ksize_per_token(self):
        return self.get_size_per_token()

    def get_mapping_lengths(self) -> list[int]:
        token_layer_bytes = self.size * self.num_mamba_layers
        return [
            token_layer_bytes
            * self.temporal_state_elem_size
            * self.temporal_dtype.itemsize,
            *(
                token_layer_bytes * elem_size * self.conv_dtype.itemsize
                for elem_size in self.conv_state_elem_sizes
            ),
            *(
                self.size * state[0].numel() * state.element_size()
                for state in self.slot_state_device_tensors
            ),
        ]

    @staticmethod
    def _item_size_per_index(tensor: torch.Tensor) -> int:
        if tensor.shape[0] == 0:
            return 0
        return int(tensor[0].numel() * tensor.element_size())

    @staticmethod
    def _slots_are_strided(tensor: torch.Tensor) -> bool:
        """Whether slot stride differs from the slot size transfer kernels expect."""
        return (
            tensor.dim() >= 1
            and tensor.shape[0] > 0
            and tensor.stride(0) != tensor[0].numel()
        )

    @staticmethod
    def _copy_tensor_pf_lf(
        src: torch.Tensor,
        dst: torch.Tensor,
        src_indices: torch.Tensor,
        dst_indices: torch.Tensor,
        layer_id: int,
        num_layers: int,
        io_backend: str,
    ) -> None:
        if src_indices.numel() == 0:
            return
        if MambaPoolHost._slots_are_strided(dst):
            # Transfer into contiguous staging, then scatter into the strided view.
            staged = torch.empty(
                (dst_indices.numel(), *dst.shape[1:]),
                dtype=dst.dtype,
                device=dst.device,
            )
            MambaPoolHost._copy_tensor_pf_lf(
                src,
                staged,
                src_indices,
                torch.arange(staged.shape[0], device=staged.device),
                layer_id,
                num_layers,
                io_backend,
            )
            dst.index_copy_(0, dst_indices.to(dst.device), staged)
            return
        if io_backend == "kernel":
            item_size = MambaPoolHost._item_size_per_index(dst)
            # The Mamba transfer kernel wants both index tensors on the device;
            # host_indices may be on CPU (kept there by start_writing when
            # can_use_write_back_jit is True on the HostPoolGroup).
            if src_indices.device != dst_indices.device:
                src_indices = src_indices.to(dst_indices.device, non_blocking=True)
            transfer_kv_mamba_pf_lf(
                src=src,
                dst=dst,
                src_indices=src_indices,
                dst_indices=dst_indices,
                layer_id=layer_id,
                item_size=item_size,
                src_layout_dim=item_size * num_layers,
            )
        elif io_backend == "direct":
            transfer_kv_per_layer_direct_pf_lf(
                src_ptrs=[src],
                dst_ptrs=[dst],
                src_indices=src_indices,
                dst_indices=dst_indices,
                layer_id=layer_id,
                page_size=1,
            )
        else:
            raise ValueError(f"Unsupported io_backend: {io_backend}")

    @staticmethod
    def _copy_tensor_all_layers_lf_pf(
        src_layers: torch.Tensor | Sequence[torch.Tensor],
        dst: torch.Tensor,
        src_indices: torch.Tensor,
        dst_indices: torch.Tensor,
        num_layers: int,
        io_backend: str,
        src_ptrs: torch.Tensor,
        staging: Optional[torch.Tensor] = None,
        can_use_jit: bool = False,
    ) -> None:
        if src_indices.numel() == 0:
            return
        if (
            _use_xpu_mamba_ops
            and io_backend == "kernel"
            and (
                not isinstance(src_layers, torch.Tensor)
                or MambaPoolHost._slots_are_strided(src_layers[0])
            )
        ):
            # The XPU op takes one contiguous layer-first tensor; draft layers are
            # separate allocations and unified slots strided, so stack in chunks.
            first = src_layers[0]
            src_indices = src_indices.to(first.device)
            layer_count = len(src_layers)
            slot_numel = first[0].numel()
            slot_bytes = layer_count * MambaPoolHost._item_size_per_index(first)
            chunk = min(
                src_indices.numel(),
                max(1, _XPU_STACK_CHUNK_BYTES // max(1, slot_bytes)),
            )
            # Reused by every chunk: a chunk's gather queues behind the previous
            # chunk's kernel on the same stream, so peak stays at one chunk.
            buffer = torch.empty(
                layer_count * chunk * slot_numel, dtype=first.dtype, device=first.device
            )
            for start in range(0, src_indices.numel(), chunk):
                chunk_indices = src_indices[start : start + chunk]
                n = chunk_indices.numel()
                stacked = buffer[: layer_count * n * slot_numel].view(
                    layer_count, n, *first.shape[1:]
                )
                for i, layer in enumerate(src_layers):
                    torch.index_select(layer, 0, chunk_indices, out=stacked[i])
                MambaPoolHost._copy_tensor_all_layers_lf_pf(
                    stacked,
                    dst,
                    torch.arange(n, device=stacked.device),
                    dst_indices[start : start + chunk],
                    num_layers,
                    io_backend,
                    src_ptrs,
                    staging=staging,
                    can_use_jit=can_use_jit,
                )
            return
        if MambaPoolHost._slots_are_strided(src_layers[0]):
            # Stage contiguous slots per layer and pass the staging buffer's pointers.
            staged = torch.stack(
                [
                    src_layers[i].index_select(0, src_indices.to(src_layers.device))
                    for i in range(num_layers)
                ]
            )
            staged_ptrs = torch.tensor(
                [staged[i].data_ptr() for i in range(num_layers)],
                dtype=torch.uint64,
                device=staged.device,
            )
            MambaPoolHost._copy_tensor_all_layers_lf_pf(
                staged,
                dst,
                torch.arange(staged.shape[1], device=staged.device),
                dst_indices,
                num_layers,
                io_backend,
                staged_ptrs,
                staging=staging,
                can_use_jit=can_use_jit,
            )
            return
        if io_backend == "kernel":
            item_size = MambaPoolHost._item_size_per_index(src_layers[0])
            if _use_xpu_mamba_ops:
                transfer_kv_mamba_lf_pf(
                    src_layers=src_layers,
                    dst=dst,
                    src_indices=src_indices,
                    dst_indices=dst_indices,
                    item_size=item_size,
                    dst_layout_dim=item_size * num_layers,
                    num_layers=num_layers,
                )
                return
            transfer_kv_mamba_lf_pf(
                src_ptrs=src_ptrs,
                dst=dst,
                src_indices=src_indices,
                dst_indices=dst_indices,
                item_size=item_size,
                dst_layout_dim=item_size * num_layers,
                num_layers=num_layers,
            )
        elif io_backend == "direct":
            src_ptrs = [src_layers[i] for i in range(num_layers)]
            transfer_kv_all_layer_direct_lf_pf(
                src_ptrs=src_ptrs,
                dst_ptrs=[dst],
                src_indices=src_indices,
                dst_indices=dst_indices,
                page_size=1,
            )
        else:
            raise ValueError(f"Unsupported io_backend: {io_backend}")

    def load_to_device_per_layer(
        self,
        device_pool,
        host_indices,
        device_indices,
        layer_id,
        io_backend="kernel",
        *,
        is_draft: bool = False,
    ):
        temporal_layers = (
            self.temporal_device_layers
            if self.mtp_draft_buffer_infos
            else self.buffer_info.temporal
        )
        conv_layers = (
            self.conv_device_layers
            if self.mtp_draft_buffer_infos
            else self.buffer_info.conv
        )

        # Side state is not per-layer, so it rides on the first layer's call --
        # before that layer's completion event, which is what every reader of a
        # restored slot waits on.
        if io_backend == "kernel_ascend":
            # NPU: the split-KV operator covers every component, side states
            # included (they ride layer 0), so the torch ride-along below must
            # not run.
            self._load_to_device_kv_split(host_indices, device_indices, layer_id)

        else:
            # no ssm state on conv-only models: nothing to transfer
            if layer_id == 0:
                self._transfer_slot_states(host_indices, device_indices, to_device=True)
            if self.temporal_state_elem_size > 0:
                self._copy_tensor_pf_lf(
                    src=self.temporal_buffer,
                    dst=temporal_layers[layer_id],
                    src_indices=host_indices,
                    dst_indices=device_indices,
                    layer_id=layer_id,
                    num_layers=self.num_mamba_layers,
                    io_backend=io_backend,
                )
            for conv_idx in range(len(self.conv_state_shapes)):
                self._copy_tensor_pf_lf(
                    src=self.conv_buffer[conv_idx],
                    dst=conv_layers[conv_idx][layer_id],
                    src_indices=host_indices,
                    dst_indices=device_indices,
                    layer_id=layer_id,
                    num_layers=self.num_mamba_layers,
                    io_backend=io_backend,
                )

    def backup_from_device_all_layer(
        self, device_pool, host_indices, device_indices, io_backend="kernel"
    ):
        temporal_layers = (
            self.temporal_device_layers
            if self.mtp_draft_buffer_infos
            else self.buffer_info.temporal
        )
        conv_layers = (
            self.conv_device_layers
            if self.mtp_draft_buffer_infos
            else self.buffer_info.conv
        )
        if io_backend == "kernel_ascend":
            # NPU: the split-KV operator covers side states as components, so
            # the torch tail below must not run.
            self._backup_from_device_kv_split(host_indices, device_indices)
            return
        if io_backend == "kernel" and host_indices.device != device_indices.device:
            # The mamba JIT kernel wants both index tensors on the device;
            # the staged MHA/MLA write path hands us CPU host indices.
            # Convert once here rather than per conv/temporal tensor.
            host_indices = host_indices.to(device_indices.device, non_blocking=True)
        # no ssm state on conv-only models: a 0-size batched memcpy errors
        if self.temporal_state_elem_size > 0:
            self._copy_tensor_all_layers_lf_pf(
                src_layers=temporal_layers,
                dst=self.temporal_buffer,
                src_indices=device_indices,
                dst_indices=host_indices,
                num_layers=self.num_mamba_layers,
                io_backend=io_backend,
                staging=self.temporal_staging_buffer,
                can_use_jit=self._temporal_can_use_jit,
                src_ptrs=self.temporal_device_ptrs,
            )
        for conv_idx in range(len(self.conv_state_shapes)):
            self._copy_tensor_all_layers_lf_pf(
                src_layers=conv_layers[conv_idx],
                dst=self.conv_buffer[conv_idx],
                src_indices=device_indices,
                dst_indices=host_indices,
                num_layers=self.num_mamba_layers,
                io_backend=io_backend,
                staging=self.conv_staging_buffers[conv_idx],
                can_use_jit=self._conv_can_use_jit[conv_idx],
                src_ptrs=self.conv_device_ptrs[conv_idx],
            )
        self._transfer_slot_states(host_indices, device_indices, to_device=False)

    def _transfer_slot_states(self, host_indices, device_indices, *, to_device):
        """Copy the registered side-state rows for these slots, one leg or the
        other. Blocking copies: the rows are a few hundred KB per checkpoint and
        correctness of the ordering against the completion event matters more
        than the microseconds."""
        if not self.slot_state_device_tensors:
            return
        for state, host_buf in zip(
            self.slot_state_device_tensors, self.slot_state_buffers
        ):
            dev_idx = device_indices.reshape(-1).to(
                device=state.device, dtype=torch.long
            )
            host_idx = host_indices.reshape(-1).to(
                device=host_buf.device, dtype=torch.long
            )
            if to_device:
                values = host_buf.index_select(0, host_idx)
                state.index_copy_(0, dev_idx, values.to(state.device))
            else:
                values = state.index_select(0, dev_idx)
                host_buf.index_copy_(0, host_idx, values.to(host_buf.device))

    def get_data_page(self, index, flat: bool = True) -> torch.Tensor:
        data_page = torch.cat(
            [
                self._flatten_tensor_bytes(tensor)
                for tensor in self._iter_page_tensors(index)
            ]
        )
        return data_page.flatten() if flat else data_page

    def get_dummy_flat_data_page(self) -> torch.Tensor:
        return torch.zeros(
            self.page_size * self.size_per_token,
            dtype=torch.uint8,
            device=self.device,
            pin_memory=self.pin_memory,
        )

    def set_from_flat_data_page(
        self,
        index: int,
        data_page: torch.Tensor,
    ) -> None:
        flat_bytes = data_page.contiguous().view(torch.uint8).reshape(-1)
        expected = self.page_size * self.size_per_token
        if self.slot_state_device_tensors and flat_bytes.numel() != expected:
            # A page stored by a build without the side state is shorter; say so
            # instead of failing inside a reshape halfway through the restore.
            raise ValueError(
                f"Mamba state page has {flat_bytes.numel()} bytes, expected "
                f"{expected}: the page predates registered slot side states."
            )
        start = 0
        for tensor in self._iter_page_tensors(index):
            num_bytes = tensor.numel() * tensor.element_size()
            tensor_bytes = flat_bytes[start : start + num_bytes]
            start += num_bytes
            if tensor_bytes.storage_offset() % tensor.element_size():
                # With side state the page holds components of different element
                # sizes, so a later component can begin at a byte offset its own
                # dtype cannot be viewed at. A contiguous copy re-bases it at 0.
                tensor_bytes = tensor_bytes.clone()
            restored = tensor_bytes.view(dtype=tensor.dtype).reshape(tensor.shape)
            tensor.copy_(restored)

    def get_page_buffer_meta(self, indices):
        """Meta data for zero-copy storage I/O.

        Only page-first layouts are supported for mamba storage zero-copy because
        each page slot in temporal/conv buffers is directly addressable.
        """
        if self.slot_state_device_tensors:
            raise NotImplementedError(
                "Mamba storage zero-copy does not carry registered slot side "
                "states; use a whole-page storage backend."
            )
        assert len(indices) % self.page_size == 0
        if self.layout not in ["page_first", "page_first_direct"]:
            raise ValueError(
                f"Mamba storage zero-copy requires page_first layout, got {self.layout}"
            )
        indices = indices.tolist()
        ptr_list = []
        element_size_list = []

        # Compute base pointers once; each page pointer is offset from these bases.
        temporal_base_ptr = self.temporal_buffer.data_ptr()
        conv_base_ptrs = [buf.data_ptr() for buf in self.conv_buffer]
        # Component sizes are constant across pages, so precompute once as well.
        temporal_element_size = (
            self.page_size
            * self.num_mamba_layers
            * self.temporal_dtype.itemsize
            * self.temporal_state_elem_size
        )
        conv_element_sizes = [
            (
                self.page_size
                * self.num_mamba_layers
                * self.conv_dtype.itemsize
                * self.conv_state_elem_sizes[i]
            )
            for i in range(len(self.conv_state_shapes))
        ]

        for i in range(0, len(indices), self.page_size):
            # Emit component pointers in stable order: temporal first (dropped
            # for conv-only models with no ssm state), then conv_0..conv_n.
            # _get_hybrid_page_component_keys drops the temporal key under the
            # same condition, keeping keys and buffers aligned.
            if self.temporal_state_elem_size > 0:
                temporal_ptr = (
                    temporal_base_ptr
                    + indices[i]
                    * self.num_mamba_layers
                    * self.temporal_state_elem_size
                    * self.temporal_dtype.itemsize
                )
                ptr_list.append(temporal_ptr)
                element_size_list.append(temporal_element_size)
            for j in range(len(self.conv_buffer)):
                conv_ptr = (
                    conv_base_ptrs[j]
                    + indices[i]
                    * self.num_mamba_layers
                    * self.conv_state_elem_sizes[j]
                    * self.conv_dtype.itemsize
                )
                ptr_list.append(conv_ptr)
                element_size_list.append(conv_element_sizes[j])
        return ptr_list, element_size_list

    def is_stride_page_aligned(self, page_size_bytes: int = 4096) -> bool:
        if self.slot_state_device_tensors:
            # Side-state rows are a second, differently-strided buffer: a page is
            # no longer one contiguous slice, so no zero-copy claim is made.
            return False
        if self.layout not in ["page_first", "page_first_direct"]:
            return False
        temporal_stride = (
            self.num_mamba_layers
            * self.temporal_state_elem_size
            * self.temporal_dtype.itemsize
        )
        if self.temporal_buffer.data_ptr() % page_size_bytes != 0:
            return False
        if temporal_stride % page_size_bytes != 0:
            return False
        for buf, elem_size in zip(self.conv_buffer, self.conv_state_elem_sizes):
            conv_stride = self.num_mamba_layers * elem_size * self.conv_dtype.itemsize
            if buf.data_ptr() % page_size_bytes != 0:
                return False
            if conv_stride % page_size_bytes != 0:
                return False
        return True

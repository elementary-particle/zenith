"""GPU PPO 推理 actor:V18 输入的跨 worker 批处理。"""

from __future__ import annotations

import asyncio
import concurrent.futures
import gc
import time
from contextlib import contextmanager
from pathlib import Path
from typing import Any

import numpy as np
import torch
from torch.nn import functional as F

try:
    import ray
except ImportError:
    ray = None

from ..model import KyokuTransformerActorCritic, ModelConfig
from ..model.dense_embedding import compute_kind_row_plan
from ..model.encoding_protocol import CONTEXT_TOKENS, TOKEN_NUMERIC_WIDTH, TOKEN_ROW_WIDTH
from ..model.schema import NUM_ACTIONS
from .profiling import StageProfiler


def parse_history_namespace(namespace: str) -> int:
    """Parse ``history:uNNN`` into the frozen checkpoint update number."""
    label = str(namespace).removeprefix("history:").removeprefix("u")
    if not label.isdigit():
        raise RuntimeError(f"malformed history namespace {namespace!r}")
    return int(label)


def inference_autocast_config(dtype_name: str, *, device_type: str = "cuda") -> tuple[torch.dtype, bool]:
    """按配置解析 rollout autocast dtype;FP32 明确关闭 autocast。"""
    normalized = str(dtype_name).lower()
    if normalized in {"fp32", "float32"}:
        return torch.float32, False
    if normalized in {"bf16", "bfloat16"}:
        enabled = bool(device_type == "cuda" and torch.cuda.is_bf16_supported())
        return torch.bfloat16, enabled
    raise ValueError("inference_dtype must be one of 'bf16' or 'fp32'")


# 到齐即 flush 的默认最低独立 worker 数:凑批窗口内到达的独立 worker 数
# 达到该值即视为「批已到齐」立即 flush,避免 12 worker 各 ~32 行时全额睡满
# 窗口(实测 100% dispatch 由超时触发)。单一 worker 的多行请求不触发
# (由行数阈值/超时兜底),保持大请求不被切碎。
MIN_QUORUM_WORKERS = 2


def dispatch_reason(
    worker_ids: list[int], target_workers: int, deadline: float, now: float,
    *, row_count: int = 0, target_rows: int | None = None,
    batch_wait_s: float = 0.0, min_quorum_workers: int = MIN_QUORUM_WORKERS,
) -> str | None:
    """Return why a pending inference batch may flush, without clock I/O.

    判定顺序:行数阈值 → 到齐即 flush(凑批窗口已打开且独立 worker 数达到
    ``min_quorum_workers``)→ 目标 worker 数 → 截止超时。``batch_wait_s`` 为
    凑批窗口已等待时长,非正值时保持旧行为(纯行数/target/超时判定)。
    """
    if target_rows is not None and row_count >= target_rows:
        return "rows"
    if (
        batch_wait_s > 0.0
        and min_quorum_workers > 0
        and len(set(worker_ids)) >= min_quorum_workers
    ):
        return "quorum"
    if len(set(worker_ids)) >= max(1, target_workers):
        return "target"
    if now >= deadline:
        return "timeout"
    return None


def collate_request_rows(
    requests: list[dict[str, Any]], group: list[tuple[int, int]],
) -> tuple[
    np.ndarray, np.ndarray, np.ndarray, np.ndarray,
    np.ndarray, np.ndarray, np.ndarray, np.ndarray,
]:
    """把选中请求行按 V18 完整 Actor 序列 host-padding,保留请求/行映射。"""
    if not group:
        raise ValueError("cannot collate an empty inference group")

    def column(name: str, dtype: np.dtype) -> np.ndarray:
        return np.asarray(
            [requests[request_index][name][row] for request_index, row in group],
            dtype=dtype,
        )

    actor_lengths = column("actor_lengths", np.int64)
    pair_counts = column("query_pair_counts", np.int64)
    critic_lengths = column("critic_lengths", np.int64)
    max_actor = int(actor_lengths.max())
    max_pairs = int(pair_counts.max())
    max_critic = int(critic_lengths.max(initial=0))
    batch = len(group)
    # 索引型字段直接以 int64 分配并写入:模型 embedding 需要 long,直接在
    # copy 时转型,省去旧路径「int32 拼装 → 整块 .astype(int64) 再拷贝」。
    actor_factors = np.zeros((batch, max_actor, TOKEN_ROW_WIDTH), dtype=np.int64)
    actor_numeric = np.zeros((batch, max_actor, TOKEN_NUMERIC_WIDTH), dtype=np.float32)
    query_action_ids = np.zeros((batch, max_pairs), dtype=np.int64)
    critic_factors = np.zeros((batch, max_critic, TOKEN_ROW_WIDTH), dtype=np.int64)
    legal = np.empty((batch, NUM_ACTIONS), dtype=np.bool_)
    for index, (request_index, row) in enumerate(group):
        request = requests[request_index]
        actor_length = int(actor_lengths[index])
        actor_factors[index, :actor_length] = request["actor_factors"][row, :actor_length]
        actor_numeric[index, :actor_length] = request["actor_numeric"][row, :actor_length]
        pair_count = int(pair_counts[index])
        query_action_ids[index, :pair_count] = request["query_action_ids"][row, :pair_count]
        critic_length = int(critic_lengths[index])
        if critic_length:
            critic_factors[index, :critic_length] = request["critic_factors"][row, :critic_length]
        legal[index] = request["legal_mask"][row]
    return (
        actor_factors,
        actor_numeric,
        actor_lengths,
        query_action_ids,
        pair_counts,
        critic_factors,
        critic_lengths,
        legal,
    )


def assign_batch_outputs(
    responses: list[dict[str, Any]],
    group: list[tuple[int, int]],
    action_ids: list[int],
    logprobs: list[float],
    values: list[float],
) -> None:
    """Route batched model outputs back to their original RPC and row."""
    if not (
        len(group) == len(action_ids) == len(logprobs) == len(values)
    ):
        raise ValueError("inference output dimensions differ")
    for index, (request_index, row) in enumerate(group):
        responses[request_index]["action_ids"][row] = int(action_ids[index])
        responses[request_index]["logprobs"][row] = float(logprobs[index])
        responses[request_index]["values"][row] = float(values[index])


if ray is not None:
    @ray.remote(num_gpus=1, max_concurrency=128)
    class RolloutInferenceActor:
        """一个 GPU 推理 owner:按 namespace 持有 rollout/SFT/历史模型。

        PPO 优化器由 driver 侧 learner 持有;每个 update 后 driver 经
        ``update_weights`` 把最新权重推送到本 actor,worker 的 rollout 请求由
        本 actor 跨 worker 批处理。
        """

        def __init__(self, config: dict[str, Any]) -> None:
            if not torch.cuda.is_available():
                raise RuntimeError("central rollout inference requires CUDA")
            self.config = config
            self.device = torch.device("cuda", 0)
            torch.cuda.set_device(0)
            self.model_config = self._model_config()
            self.model = KyokuTransformerActorCritic(self.model_config).to(self.device)
            self.model.eval()
            self.autocast_dtype, self.autocast_enabled = inference_autocast_config(
                str(config.get("inference_dtype", "bf16")),
                device_type=self.device.type,
            )
            self._weights: dict[str, torch.Tensor] | None = None
            self.sft_model: torch.nn.Module | None = None
            self.history_models: dict[str, torch.nn.Module] = {}
            # 按名称复用的 pinned host 缓冲:消除每 dispatch 的 pageable H2D
            # 同步等待与临时分配(H2D 用 non_blocking 异步发起)。
            self._pinned_pool: dict[str, torch.Tensor] = {}
            self.profiler = StageProfiler(enabled=bool(config.get("profile_enabled", True)))
            self.profile_cuda_sync = bool(config.get("profile_cuda_sync", False))
            self.cuda_event_interval = max(0, int(config.get("profile_cuda_event_interval", 100)))
            self._forward_calls = 0
            self._pending: list[tuple[dict[str, Any], asyncio.Future[dict[str, Any]], float]] = []
            self._pending_event = asyncio.Event()
            self._drain_task: asyncio.Task[None] | None = None
            self._profile_checkpoint = self.profiler.checkpoint()
            self._counter_checkpoint: dict[str, float] = {}
            self._counters: dict[str, float] = {}
            self._rollout_forward_max_tokens: list[int] = []
            self._rollout_target_workers = int(
                config.get("inference_actor_num_workers", config.get("num_workers", 1))
            )
            # 事件循环解耦计算执行器:单线程即可(同一时间只有一个 dispatch
            # 计算在飞,与旧串行时序等价),避免多线程并发触碰 CUDA 上下文。
            self._compute_executor = concurrent.futures.ThreadPoolExecutor(
                max_workers=1, thread_name_prefix="riichi-inference-compute",
            )

        def _model_config(self) -> ModelConfig:
            values = vars(ModelConfig.preset("v18"))
            # fallback 单源对齐 V18 契约上界;配置缺省时不得放大窗口。
            values["context_tokens"] = int(self.config.get("context_tokens", CONTEXT_TOKENS))
            return ModelConfig(**values)

        def _sync_cuda(self) -> None:
            if self.profile_cuda_sync:
                torch.cuda.synchronize(self.device)

        def _pinned_capacity_shape(
            self, name: str, value: np.ndarray,
        ) -> tuple[int, ...]:
            """按配置上限返回该字段的 pinned 缓冲容量(每名 actor 只分配一次)。"""
            batch_cap = max(1, int(self.config.get("inference_max_batch_size", 512)))
            token_cap = max(1, int(self.config.get("context_tokens", CONTEXT_TOKENS)))
            if name in {"actor_factors", "critic_factors"}:
                return (batch_cap, token_cap, int(value.shape[2]))
            if name == "actor_numeric":
                return (batch_cap, token_cap, int(value.shape[2]))
            if name == "query_action_ids":
                return (batch_cap, token_cap)
            if name == "legal":
                return (batch_cap, int(value.shape[1]))
            if name in {"actor_lengths", "pair_counts", "critic_lengths"}:
                return (batch_cap,)
            return tuple(value.shape)

        def _host_tensor_to_device(
            self, name: str, value: np.ndarray,
        ) -> torch.Tensor:
            """host 数组 → 设备张量:复用 pinned 缓冲并以 non_blocking 发起 H2D。

            旧路径为 ``astype(int64) 全量拷贝 + torch.as_tensor(device)`` 的
            同步 pageable 传输;新路径只做一次 pinned 视图复制 + 异步 DMA,
            数值逐位一致(纯数据通路优化,不改模型输入值)。
            """
            if self.device.type != "cuda":
                return torch.from_numpy(np.ascontiguousarray(value))
            host = torch.from_numpy(np.ascontiguousarray(value))
            pinned = self._pinned_pool.get(name)
            if pinned is None:
                pinned = torch.empty(
                    self._pinned_capacity_shape(name, value),
                    dtype=host.dtype,
                    pin_memory=True,
                )
                self._pinned_pool[name] = pinned
            view = pinned[tuple(slice(0, dim) for dim in host.shape)]
            view.copy_(host)
            return view.to(self.device, non_blocking=True)

        @contextmanager
        def _gpu_stage(self, name: str):
            """Measure submitted GPU work; exact fencing is diagnostic-only."""
            self._sync_cuda()
            with self.profiler.stage(name):
                try:
                    yield
                finally:
                    self._sync_cuda()

        def _add_counter(self, name: str, value: float = 1.0) -> None:
            self._counters[name] = self._counters.get(name, 0.0) + float(value)

        def _target_workers(self) -> int:
            configured = int(self.config.get("inference_batch_target_workers", 0))
            if configured < 0:
                # 负值显式禁用「按 worker 数触发」,只按行数阈值或超时 flush,
                # 避免 6 个 worker 各自 ~32 行时过早切成小批。
                return 1 << 30
            return max(1, configured or self._rollout_target_workers)

        def release_cache(self) -> None:
            """评测前释放本 actor 的缓存显存(与 learner 释放同机制)。"""
            gc.collect()
            torch.cuda.empty_cache()

        def update_weights(self, weights: dict[str, torch.Tensor]) -> dict[str, float]:
            """接收 driver learner 的最新权重并加载到 rollout 模型。"""
            self._weights = {
                name: value.to(self.device) for name, value in weights.items()
            }
            self.model.load_state_dict(self._weights, strict=True)
            self.model.eval()
            return {}

        def begin_rollout(self, update: int) -> None:
            """开始一个 on-policy rollout,重置本迭代的耗时/计数基线。"""
            self._profile_checkpoint = self.profiler.checkpoint()
            self._counter_checkpoint = dict(self._counters)
            self._rollout_forward_max_tokens = []
            self._rollout_target_workers = int(
                self.config.get(
                    "inference_actor_num_workers", self.config.get("num_workers", 1)
                )
            )

        def _model_for_namespace(self, namespace: str) -> torch.nn.Module:
            if namespace == "rollout":
                return self.model
            if namespace == "sft":
                return self._sft_model()
            if namespace.startswith("history:"):
                return self._history_model(namespace)
            raise RuntimeError(f"unknown inference namespace {namespace!r}")

        def _sft_model(self) -> torch.nn.Module:
            if self.sft_model is None:
                path = Path(self.config["init_model"])
                payload = torch.load(path, map_location="cpu", weights_only=False)
                model = KyokuTransformerActorCritic(self.model_config).to(self.device)
                model.load_state_dict(payload["model"], strict=True)
                model.eval()
                model.requires_grad_(False)
                self.sft_model = model
            return self.sft_model

        def _history_model(self, namespace: str) -> torch.nn.Module:
            """Lazily load one frozen historical PPO checkpoint, then cache it."""
            if namespace in self.history_models:
                return self.history_models[namespace]
            update = parse_history_namespace(namespace)
            path = Path(self.config["checkpoint_dir"]) / f"checkpoint_{update:05d}.pt"
            if not path.is_file():
                raise RuntimeError(
                    f"historical checkpoint missing: {path} (requested {namespace})"
                )
            payload = torch.load(path, map_location="cpu", weights_only=False)
            if not isinstance(payload, dict):
                raise RuntimeError(f"invalid historical checkpoint: {path}")
            state = payload.get("model")
            if not isinstance(state, dict):
                raise RuntimeError(f"historical checkpoint is missing model weights: {path}")
            model = KyokuTransformerActorCritic(self.model_config).to(self.device)
            model.load_state_dict(state, strict=True)
            model.eval()
            model.requires_grad_(False)
            self.history_models[namespace] = model
            return model

        def rng_state(self) -> dict[str, Any]:
            return {
                "torch_rng": torch.get_rng_state().cpu(),
                "cuda_rng": torch.cuda.get_rng_state(self.device).cpu(),
            }

        def load_rng_state(self, state: dict[str, Any]) -> None:
            torch.set_rng_state(state["torch_rng"].cpu())
            torch.cuda.set_rng_state(state["cuda_rng"].cpu(), self.device)

        def shutdown(self) -> None:
            self.history_models.clear()
            self.sft_model = None
            self._compute_executor.shutdown(wait=False)

        def profile_summary(self) -> dict[str, float]:
            """Return one iteration's actor totals without RPC fan-out double counting."""
            stats = self.profiler.delta(self._profile_checkpoint, prefix="timing")
            counters = {
                name: value - self._counter_checkpoint.get(name, 0.0)
                for name, value in self._counters.items()
            }
            dispatches = counters.get("inference/dispatches", 0.0)
            forwards = counters.get("inference/full_forwards", 0.0)
            stats.update(counters)
            stats["inference/dispatch_rows_mean"] = counters.get("inference/dispatch_rows", 0.0) / max(dispatches, 1.0)
            stats["inference/dispatch_workers_mean"] = counters.get(
                "inference/dispatch_workers", 0.0,
            ) / max(dispatches, 1.0)
            stats["inference/full_forward_rows_mean"] = counters.get(
                "inference/full_forward_rows", 0.0,
            ) / max(forwards, 1.0)
            effective_tokens = counters.get("inference/effective_input_tokens", 0.0)
            padded_tokens = counters.get("inference/padded_input_tokens", 0.0)
            padding_tokens = counters.get("inference/padding_input_tokens", 0.0)
            stats["inference/padding_to_effective_token_ratio"] = padding_tokens / max(effective_tokens, 1.0)
            stats["inference/padding_fraction_of_padded_tokens"] = padding_tokens / max(padded_tokens, 1.0)
            if self._rollout_forward_max_tokens:
                input_lengths = np.asarray(self._rollout_forward_max_tokens, dtype=np.int64)
                prefix = "inference/full_forward_max_input_tokens"
                stats[f"{prefix}/min"] = float(input_lengths.min())
                stats[f"{prefix}/mean"] = float(input_lengths.mean())
                stats[f"{prefix}/p50"] = float(np.percentile(input_lengths, 50))
                stats[f"{prefix}/p90"] = float(np.percentile(input_lengths, 90))
                stats[f"{prefix}/p99"] = float(np.percentile(input_lengths, 99))
                stats[f"{prefix}/max"] = float(input_lengths.max())
            return stats

        async def infer(
            self,
            *,
            worker_id: int,
            namespace: str,
            batch_indices: np.ndarray,
            actor_factors: np.ndarray,
            actor_numeric: np.ndarray,
            actor_lengths: np.ndarray,
            query_action_ids: np.ndarray,
            query_pair_counts: np.ndarray,
            legal_mask: np.ndarray,
            critic_factors: np.ndarray,
            critic_lengths: np.ndarray,
            greedy: bool,
        ) -> dict[str, Any]:
            if (
                len(batch_indices) != len(actor_lengths)
                or actor_factors.shape[0] != len(batch_indices)
                or actor_numeric.shape[0] != len(batch_indices)
            ):
                raise ValueError("decision metadata batch dimensions differ")
            if (
                query_action_ids.shape[0] != len(batch_indices)
                or len(query_pair_counts) != len(batch_indices)
            ):
                raise ValueError("query metadata batch dimensions differ")
            if (
                legal_mask.shape[0] != len(batch_indices)
                or critic_factors.shape[0] != len(batch_indices)
                or len(critic_lengths) != len(batch_indices)
            ):
                raise ValueError("critic metadata batch dimensions differ")
            loop = asyncio.get_running_loop()
            future: asyncio.Future[dict[str, Any]] = loop.create_future()
            self._pending.append(({
                "worker_id": int(worker_id),
                "namespace": str(namespace),
                "batch_indices": batch_indices,
                "actor_factors": actor_factors,
                "actor_numeric": actor_numeric,
                "actor_lengths": actor_lengths,
                "query_action_ids": query_action_ids,
                "query_pair_counts": query_pair_counts,
                "legal_mask": legal_mask,
                "critic_factors": critic_factors,
                "critic_lengths": critic_lengths,
                "greedy": bool(greedy),
            }, future, time.perf_counter()))
            self._pending_event.set()
            if self._drain_task is None:
                self._drain_task = asyncio.create_task(self._drain_requests())
            return await future

        async def _drain_requests(self) -> None:
            try:
                loop = asyncio.get_running_loop()
                while self._pending:
                    target_workers = self._target_workers()
                    target_rows = max(
                        1,
                        int(self.config.get("inference_batch_target_rows", 0))
                        or int(self.config.get("inference_max_batch_size", 512)),
                    )
                    window_s = max(
                        0.0, float(self.config.get("inference_batch_wait_ms", 5.0))
                    ) / 1_000.0
                    batch_opened = time.perf_counter()
                    deadline = batch_opened + window_s
                    # 到齐即 flush 的独立 worker 数下限:0/负值显式禁用(保持
                    # 纯超时凑批);未配置时默认 MIN_QUORUM_WORKERS。
                    quorum = int(self.config.get("inference_batch_min_workers", MIN_QUORUM_WORKERS))
                    flush_reason: str | None = None
                    while flush_reason is None:
                        now = time.perf_counter()
                        flush_reason = dispatch_reason(
                            [request["worker_id"] for request, _future, _queued_at in self._pending],
                            target_workers, deadline, now,
                            row_count=sum(
                                len(request["batch_indices"]) for request, _future, _queued_at in self._pending
                            ),
                            target_rows=target_rows,
                            # 凑批窗口已打开(有等待预算)才允许到齐判定:
                            # 窗口为 0 时退化为立即 flush,与旧超时语义一致。
                            batch_wait_s=(deadline - now) if window_s > 0.0 else 0.0,
                            min_quorum_workers=quorum,
                        )
                        if flush_reason is not None:
                            break
                        remaining = deadline - time.perf_counter()
                        self._pending_event.clear()
                        try:
                            await asyncio.wait_for(self._pending_event.wait(), timeout=remaining)
                        except asyncio.TimeoutError:
                            pass
                    pending, self._pending = self._pending, []
                    now = time.perf_counter()
                    workers = {request["worker_id"] for request, _future, _queued_at in pending}
                    self._add_counter("inference/rpc_requests", len(pending))
                    self._add_counter("inference/dispatches")
                    self._add_counter("inference/dispatch_workers", len(workers))
                    self._add_counter(
                        "inference/dispatch_rows",
                        sum(len(request["batch_indices"]) for request, _future, _queued_at in pending),
                    )
                    self._add_counter(f"inference/dispatch_{flush_reason or 'timeout'}")
                    for _request, _future, queued_at in pending:
                        self.profiler.add("inference/queue_wait", now - queued_at)
                    try:
                        # 事件循环解耦:_infer_many 移到线程池执行(默认线程池,
                        # 与主循环并发),RPC 接收与凑批等待不再被 host collate/
                        # H2D/GPU 前向阻塞;主循环 await 结果后回填 future。
                        # 同一时间只有一个计算任务在飞(与旧串行时序等价,
                        # 数值与顺序不变),仅消除事件循环的「计算期不响应」。
                        results = await loop.run_in_executor(
                            self._compute_executor, self._infer_many,
                            [request for request, _future, _queued_at in pending],
                        )
                        for (_request, future, _queued_at), result in zip(pending, results):
                            if not future.done():
                                future.set_result(result)
                    except Exception as exc:
                        for _request, future, _queued_at in pending:
                            if not future.done():
                                future.set_exception(exc)
            finally:
                self._drain_task = None

        def _infer_many(self, requests: list[dict[str, Any]]) -> list[dict[str, Any]]:
            started = time.perf_counter()
            responses = [
                {
                    "action_ids": [0] * len(request["batch_indices"]),
                    "logprobs": [0.0] * len(request["batch_indices"]),
                    "values": [0.0] * len(request["batch_indices"]),
                }
                for request in requests
            ]
            rows_by_mode: dict[tuple[str, bool], list[tuple[int, int]]] = {}
            for request_index, request in enumerate(requests):
                key = (str(request["namespace"]), bool(request["greedy"]))
                rows_by_mode.setdefault(key, []).extend(
                    (request_index, row) for row in range(len(request["batch_indices"]))
                )
            max_batch = max(1, int(self.config.get("inference_max_batch_size", 512)))
            for (namespace, greedy), rows in rows_by_mode.items():
                model = self._model_for_namespace(namespace)
                for offset in range(0, len(rows), max_batch):
                    group = rows[offset : offset + max_batch]
                    self._run_full_forward(requests, responses, group, greedy, model)
            self.profiler.add("inference/rpc_total", time.perf_counter() - started)
            return responses

        def _run_full_forward(
            self,
            requests: list[dict[str, Any]],
            responses: list[dict[str, Any]],
            group: list[tuple[int, int]],
            greedy: bool,
            model: torch.nn.Module,
        ) -> None:
            if not group:
                return
            with self.profiler.stage("inference/host_collate"):
                (
                    actor_factors,
                    actor_numeric,
                    actor_lengths,
                    query_action_ids,
                    pair_counts,
                    critic_factors,
                    critic_lengths,
                    legal,
                ) = collate_request_rows(requests, group)
            # C2:host 侧类别行表(纯 numpy,无同步),供 token_embedding
            # 走静态键表路径。
            kind_row_plan = compute_kind_row_plan(actor_factors)
            critic_kind_row_plan = compute_kind_row_plan(critic_factors)
            sequence_tokens = actor_lengths
            max_tokens = int(sequence_tokens.max())
            effective_input_tokens = int(sequence_tokens.sum())
            padded_input_tokens = len(group) * max_tokens
            self._add_counter("inference/effective_input_tokens", effective_input_tokens)
            self._add_counter("inference/padded_input_tokens", padded_input_tokens)
            self._add_counter(
                "inference/padding_input_tokens", padded_input_tokens - effective_input_tokens
            )
            self._rollout_forward_max_tokens.append(max_tokens)
            with self._gpu_stage("inference/h2d"):
                device_tensors = {
                    name: self._host_tensor_to_device(name, value)
                    for name, value in (
                        ("actor_factors", actor_factors),
                        ("actor_numeric", actor_numeric),
                        ("actor_lengths", actor_lengths),
                        ("query_action_ids", query_action_ids),
                        ("pair_counts", pair_counts),
                        ("critic_factors", critic_factors),
                        ("critic_lengths", critic_lengths),
                        ("legal", legal),
                    )
                }
            self._forward_calls += 1
            sample_cuda = (
                self.profiler.enabled and self.cuda_event_interval > 0
                and self._forward_calls % self.cuda_event_interval == 0
            )
            start_event = torch.cuda.Event(enable_timing=True) if sample_cuda else None
            end_event = torch.cuda.Event(enable_timing=True) if sample_cuda else None
            if start_event is not None:
                start_event.record()
            with self._gpu_stage("inference/full_forward"):
                # forward 必须包 inference_mode,否则导出的张量带 requires_grad,
                # 在无梯度上下文下 .numpy() 会直接报错。
                with torch.inference_mode(), torch.autocast(
                    device_type="cuda", dtype=self.autocast_dtype,
                    enabled=self.autocast_enabled,
                ):
                    output = model(
                        device_tensors["actor_factors"],
                        device_tensors["actor_numeric"],
                        device_tensors["actor_lengths"],
                        device_tensors["query_action_ids"],
                        device_tensors["pair_counts"],
                        device_tensors["legal"],
                        critic_factors=device_tensors["critic_factors"],
                        critic_lengths=device_tensors["critic_lengths"],
                        # 训练期 rollout 推理与 learner 共用同一配置开关:输入
                        # 由 Rust 编码器 fail-closed 生成,推理路径跳过 GPU 侧
                        # 重复校验。默认 True 保持历史行为(评测路径不受影响)。
                        validate_structure=bool(
                            self.config.get("update_validate_structure", True)
                        ),
                        kind_row_plan=kind_row_plan,
                        critic_kind_row_plan=critic_kind_row_plan,
                    )
                    logits = output["policy_logits"].float()
                    probabilities = F.softmax(logits, dim=-1)
                    chosen = (
                        logits.argmax(dim=-1)
                        if greedy
                        else torch.multinomial(probabilities, 1).squeeze(1)
                    )
                    logprob = (
                        F.log_softmax(logits, dim=-1)
                        .gather(1, chosen[:, None])
                        .squeeze(1)
                    )
                    values = output["value"].float()
                chosen_cpu = chosen.cpu().numpy().astype(np.int64).tolist()
                logprob_cpu = logprob.cpu().numpy().astype(np.float32).tolist()
                values_cpu = values.cpu().numpy().astype(np.float32).tolist()
            if end_event is not None and start_event is not None:
                end_event.record()
                end_event.synchronize()
                self.profiler.add(
                    "inference/full_forward_cuda_event",
                    start_event.elapsed_time(end_event) / 1_000.0,
                )
            self._add_counter("inference/full_forwards")
            self._add_counter("inference/full_forward_rows", len(group))
            with self._gpu_stage("inference/sample_and_d2h"):
                assign_batch_outputs(
                    responses, group, chosen_cpu, logprob_cpu, values_cpu,
                )
else:
    RolloutInferenceActor = None

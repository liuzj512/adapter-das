# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
# SPDX-License-Identifier: Apache-2.0

"""Platform-semantics seam — governance §0.5 is_cuda 路线的落地点.

adapter 统一以 CUDA 语义回答上游 sglang 的平台判定，让新模型/新功能
不经适配天然走 CUDA 分支（卡商追新）。只翻 sglang 的判定 seam，共
两个模块、五个符号：

1. ``sglang.srt.utils.common`` — is_cuda / is_hip / is_cuda_alike。
   必须在任何 sglang 模块 import 之前安装：common.py 在 import 时就用
   is_hip() 选定 FP8_E4M3_MAX 并写 builtins，全仓 `from sglang.srt.utils
   (common) import is_hip` 的常量绑定也发生在各自模块 import 时——
   判定函数换掉后这些绑定自然拿到 CUDA 语义。
2. ``sglang.srt.platforms`` — _is_cuda_available 打开 / _is_rocm_available
   关闭 → current_platform 解析为 CudaSRTPlatform。

明确不翻硬件层：torch.version、triton 编译后端选择、vllm HIP 构建的
平台判定保持 HIP 真值（全局翻 torch.version 会让 triton 走 CUDA 编译
后端直接打爆内核编译，也破坏 vllm op 探测）。内核选择层
（sglang.kernels PlatformInfo.detect）同样保持 HIP 真值，由
sitecustomize 的 capability 桥衔接——「模型层 CUDA 语义 + 内核层
HIP 真值」是本路线的合成态，两侧的翻译工作就是 adapter 的本体。

fp8 fnuz 等已验证 HIP 语义护栏不随翻（governance §0.5 白名单）：
fnuz 是卡上数学事实，不是平台判定。

开关：HCU_PLATFORM_SEMANTICS=cuda（默认，§0.5 拍板路线）| hip
（旧适配路线，降级调试 / A-B 对照用）。
"""

import logging

LOG = logging.getLogger("hcu.adapter")

# seam 目标清单（install 逐一登记 registry；target = dotted symbol）
_TARGETS = (
    "sglang.srt.utils.common:get_device_capability",
    "sglang.srt.utils.common:get_device_core_count",
    "sglang.srt.utils.common:get_device_sm",
    "sglang.srt.utils.common:get_nvgpu_memory_capacity",
    "sglang.srt.utils.common:is_cuda",
    "sglang.srt.utils.common:is_hip",
    "sglang.srt.utils.common:is_cuda_alike",
    "sglang.srt.utils.common:is_flashinfer_available",
    "sglang.srt.platforms:_is_cuda_available",
    "sglang.srt.platforms:_is_rocm_available",
    "sglang.srt.model_executor.runner_utils.shared_read_event:make_external_event",
)


def _install_gfx_probe_guard(_common):
    """Neutralize is_gfx*_supported arch probes.

    Their bodies call torch.cuda.get_device_properties(0) after the
    torch.version.hip truthy check (which we deliberately keep truthful)
    and blow up with "No CUDA GPUs are available" when visible devices are
    an offset set (HIP_VISIBLE_DEVICES=8..15) probed before CUDA init —
    exactly sitecustomize's early import order. HCU is gfx93x: every one
    of these NVIDIA/RDMA-next gates is semantically False.

    Patches BOTH namespaces: `sglang.srt.utils.common` and the re-export
    layer `sglang.srt.utils` (its __init__ does `from .common import *`,
    so late `from sglang.srt.utils import is_gfx*_supported` consumers --
    e.g. kernels/ops/quantization/fp8_kernel -- must not pick the
    ORIGINAL probe out of the package namespace). Works without _common
    too (module-import fallback for the legacy-hip/no-GPU paths).
    """
    import sglang.srt.utils as _pkg  # noqa: PLC0415 -- cheap; usually loaded
    import sglang.srt.utils.common as _c  # noqa: PLC0415 -- cheap; usually loaded

    def _false():
        return False

    targets = [_pkg, _c]
    if _common is not None and _common not in targets:
        targets.append(_common)
    for target in targets:
        for _name in list(vars(target)):
            if _name.startswith("is_gfx") and _name.endswith("_supported"):
                setattr(target, _name, _false)
    LOG.warning(
        "HCU adapter: gcn arch probes (is_gfx*) guarded to False"
        " (early-import safe under partitioned visibility)"
    )


# anchor-baseline(①改名/移位→多候选): CUDA version gates(is_sm90_supported 等)
#   — ≤v0.5.22: 冻结于 utils.common,patch common 单命名空间即够(包级
#   from .common import * 拷贝两树皆有,但 0.5.22 无人 import 期经包调用);
#   sglang main@fd19cfb(2026-11) 起 kda 后端链在模块 import 期经包命名空间
#   调用 → common+pkg 双命名空间同补,两树通吃(governance §5.3)。
def _replace_version_gates(common, pkg):
    """Rewrite the frozen lru_cache CUDA-version gates in BOTH namespaces.

    The gates (is_sm90_supported / is_ampere_with_cuda_12_3 / is_blackwell /
    ...) are lru_cache(partial(_check_cuda_device_version,...)) objects whose
    original body ends in torch.version.cuda.split -- a hard AttributeError
    with cuda=None on HCU. They are also re-exported frozen by the package
    layer's `from .common import *`, and sglang main kernels call them at
    module import time THROUGH that package namespace (e.g.
    fused_sigmoid_gating_recurrent `_is_sm90 = is_sm90_supported()` via the
    kda backend chain): patching common alone leaves the package copies
    crashing (bw47 hybrid/eager, 2026-11-05). Semantics: these gates ask for
    NVIDIA-version-specific features -- False on HCU, upstream then takes its
    conservative fallbacks. `pkg=None` patches common only (tests / no-pkg
    callers). Returns the replaced names.
    """

    def _false():
        return False

    check = getattr(common, "_check_cuda_device_version", None)
    if check is None:
        return []
    import functools as _ft

    names = []
    for name in list(vars(common)):
        inner = getattr(getattr(common, name), "__wrapped__", None)
        if isinstance(inner, _ft.partial) and inner.func is check:
            setattr(common, name, _false)
            names.append(name)
    if pkg is not None:
        for name in names:
            setattr(pkg, name, _false)
    return names


def platform_env_defaults():
    """HCU-stack platform defaults for sglang env vars (R-08 A-tier).

    Pure ``os.environ.setdefault`` calls — an explicitly exported value always
    wins (env三原则: correct deployment needs zero envs, explicit override is
    top priority). Extracted from install() so tests can pin the semantics
    without a GPU/sglang import. Landing ledger (occurrences across
    cookbook/_launch_/_test_ scripts at triage time, docs/env-vars.md §R-08):

    * SGLANG_UNIFIED_RADIX_TREE_CORE_BACKEND=python (31x) — rust TreeCore has
      no prebuilt extension on HCU; the python core is the platform fact.
      SGLANG_RUST_BUILD_MODE=never (4x) rides along (same build machinery).
    * SGLANG_ENABLE_TP_MEMORY_INBALANCE_CHECK=false (4x) — inbalance check
      fires on asymmetrical TP layouts this stack uses.
    * HCU_DEEPGEMM_BRIDGE=1 (13x) — DTK deepgemm alias+wrapper bridge,
      validated on gfx936 EP-LL and gfx938 GLM-5.3 lines; harmless when no
      DeepGEMM path runs.
    Deliberately NOT defaulted (triage verdicts): HCU_AITER_AR — the hcu_env
    auto rule is already the right default (refuses legacy layouts, allows
    the GraphSafe one); the 12 manual =0 exports predate that rule.
    SGLANG_JIT_DEEPGEMM_PRECOMPILE=0 was landed with R-04 (35037be): the
    upstream all-M precompile session is pure boot tax on the AOT DTK wheel
    (measured ~52s/shape on validation-host-26 tp4, boot 6:02→3:57; bw7 EP lines saw
    5.7-7.4GB per shape squeeze the mem budget).
    """
    import os

    os.environ.setdefault("SGLANG_SKIP_SGL_KERNEL_VERSION_CHECK", "1")
    os.environ.setdefault("SGLANG_JIT_DEEPGEMM_PRECOMPILE", "0")
    os.environ.setdefault("SGLANG_UNIFIED_RADIX_TREE_CORE_BACKEND", "python")
    os.environ.setdefault("SGLANG_RUST_BUILD_MODE", "never")
    os.environ.setdefault("SGLANG_ENABLE_TP_MEMORY_INBALANCE_CHECK", "false")
    os.environ.setdefault("HCU_DEEPGEMM_BRIDGE", "1")


# 早期 import 链（shared_read_event -> runner_utils -> ... -> dsa.utils）先于
# seam 换绑执行，`from sglang.srt.utils import is_cuda` 留下原函数（HIP 上恒
# False）。dsa.utils 的 is_graph_dsa_split_op_surface() 因此判 False，prefill
# graph 捕获里 indexer 落到 eager ragged 臂并断言 "in-graph DSA prefill must
# go through the graph DSA split-op dispatch"（S1 Hy4 2026-11-03）。只换这一处
# 的 is_cuda：其 is_hip 保持硬件真值；其他陈旧模块不动（breakable_cuda_graph
# 依赖原 is_hip() 走 torch 查询捕获状态）。
_STALE_IS_CUDA_MODULES = ("sglang.srt.layers.attention.dsa.utils",)


def _rebind_stale_is_cuda(hcu_is_cuda, registry):
    import sys as _sys

    for _name in _STALE_IS_CUDA_MODULES:
        _mod = _sys.modules.get(_name)
        if _mod is None or _mod.__dict__.get("is_cuda") is hcu_is_cuda:
            continue
        _mod.is_cuda = hcu_is_cuda
        registry.register(
            "platform_detect",
            hcu_is_cuda,
            target=f"{_name}:is_cuda",
            mechanism=registry.MECH_REBIND,
            detail="early-import stale binding (graph DSA split-op surface)",
        )


# custom AR 通信器选型是硬件问题：custom_all_reduce 在 import 时把
# is_cuda()/is_hip() 冻结进 _is_cuda/_is_hip/_is_musa，dispatch 与
# _use_amd_deterministic_impl 都读它们。首次 import 早于 seam 时冻结为 HIP
# 真值（aiter CA 生效）；#58 后首次 import 挪到 seam 之后（ar_norm_aiter ->
# _auto_aiter_ar），冻结为 CUDA 语义，dispatch 落到原生 CA 的 NVLink/NVML
# 探测失败，整组回退 RCCL（S1 Hy4 2026-11-09）。不论 import 先后都钉回硬件
# 真值。
_AR_MODULE = "sglang.srt.distributed.device_communicators.custom_all_reduce"
_AR_HW_FLAGS = (("_is_cuda", False), ("_is_hip", True), ("_is_musa", False))


def _pin_ar_hw_truth(module, registry):
    for _attr, _val in _AR_HW_FLAGS:
        if module.__dict__.get(_attr) is _val:
            continue
        setattr(module, _attr, _val)
        registry.register(
            "platform_detect",
            _val,
            target=f"{module.__name__}:{_attr}",
            mechanism=registry.MECH_REBIND,
            detail="custom AR dispatch keeps HIP hardware truth (aiter CA)",
        )


class _ArHwTruthLoader:
    def __init__(self, inner, registry):
        self._inner = inner
        self._registry = registry

    def create_module(self, spec):
        return self._inner.create_module(spec)

    def exec_module(self, module):
        self._inner.exec_module(module)
        _pin_ar_hw_truth(module, self._registry)

    def __getattr__(self, name):
        return getattr(self._inner, name)


class _ArHwTruthFinder:
    def __init__(self, registry):
        self._registry = registry

    def find_spec(self, fullname, path=None, target=None):
        import sys as _sys

        if fullname != _AR_MODULE:
            return None
        if self in _sys.meta_path:
            _sys.meta_path.remove(self)  # one-shot; also stops recursion below
        import importlib.util as _iu

        spec = _iu.find_spec(fullname)
        if spec is not None and spec.loader is not None:
            spec.loader = _ArHwTruthLoader(spec.loader, self._registry)
        return spec


def _install_ar_hw_truth(registry):
    import sys as _sys

    mod = _sys.modules.get(_AR_MODULE)
    if mod is not None:
        _pin_ar_hw_truth(mod, registry)
    elif not any(isinstance(f, _ArHwTruthFinder) for f in _sys.meta_path):
        _sys.meta_path.insert(0, _ArHwTruthFinder(registry))


def install():
    import os
    import time

    import torch

    from hcu_adapter import hcu_env, registry

    # sgl-kernel 版本门 + 平台 env 默认（R-04/R-08 A 类；上方
    # platform_env_defaults 的 docstring 是逐项落账与判由）。
    platform_env_defaults()

    sem, _src = hcu_env.resolve("HCU_PLATFORM_SEMANTICS")
    if sem != "cuda":
        LOG.warning(
            "HCU adapter: platform semantics=%r (legacy adapter route;"
            " set HCU_PLATFORM_SEMANTICS=cuda for the §0.5 is_cuda route)",
            sem,
        )
        # legacy hip 路线也要装 gcn 探针守卫：torch.version.hip 真值分支下
        # is_gfx*_supported 会裸调 get_device_properties(0)，卡分区可见性
        # （HIP_VISIBLE_DEVICES 非从 0 起）+ CUDA 未 init 的早期 import 即炸。
        _install_gfx_probe_guard(_common=None)
        return
    if not torch.cuda.is_available():
        if torch.version.hip is None:
            # 非 HIP 构建且 GPU 面完全不可见（无卡开发机等）：seam 无从谈
            # 起，gcn 守卫同样装上——后续任何 import 碰到 is_gfx* 都能拿到
            # 安全 False 而不是炸。
            _install_gfx_probe_guard(_common=None)
            return
        # HIP 构建但首轮 CUDA 探测瞬时失败：新容器里驱动枚举会与并发编译
        # （tvm_ffi dlpack 等）赛跑，数分钟后同 env 复测 device_count=8。
        # 不因瞬态弃装——下方 seam 只重写 sglang 的平台判定答案，全部是
        # 常量函数，不需要活的 CUDA 上下文；稍候重试后仍不可见则带告警
        # 照装（真正无卡时后续初始化自会响亮失败）。
        for _ in range(8):
            time.sleep(2)
            if torch.cuda.is_available():
                break
        else:
            LOG.warning(
                "HCU adapter: CUDA face unavailable at install() on a HIP"
                " build (torch.version.hip=%r) -- installing seam anyway"
                " (semantics-only, needs no live CUDA context)",
                torch.version.hip,
            )

    from sglang.srt import platforms as _pf
    from sglang.srt.utils import common as _common

    # sglang v0.5.22 没有 utils/device.py（main #48781 拆 common.py 才引入）
    # ——无守卫 import 会在这里 ImportError，把整个 platform seam（含上方
    # is_cuda 语义翻转）一并炸掉，L1 现产 0.5.22 线即此红（review #98）。
    try:
        from sglang.srt.utils import device as _device
    except ImportError:
        _device = None

    # Restore moved helpers for callers that still use the common namespace.
    if _device is not None and hasattr(_device, "get_nvgpu_memory_capacity"):
        for name in (
            "get_nvgpu_memory_capacity", "get_device_sm", "get_device_capability",
            "get_device_core_count",
        ):
            if not hasattr(_common, name):
                setattr(_common, name, getattr(_device, name))

    #这两个 import 本身会执行 common.py 顶层 `if is_hip():` ——彼时判定
    # 还是原函数，fnuz 常量已被冻结并写进 builtins；patch 后必须重算
    # （CUDA 语义 = e4m3fn，max 448）。
    _common.FP8_E4M3_MAX = float(torch.finfo(torch.float8_e4m3fn).max)
    _common.FP8_E4M3_MIN = -_common.FP8_E4M3_MAX
    import builtins as _builtins

    _builtins.FP8_E4M3_MAX = _common.FP8_E4M3_MAX
    _builtins.FP8_E4M3_MIN = _common.FP8_E4M3_MIN

    def _hcu_is_cuda():
        return True

    def _hcu_is_hip():
        return False

    def _hcu_is_cuda_alike():
        return True

    def _hcu_pf_cuda_available():
        return True

    def _hcu_pf_rocm_available():
        return False

    # flashinfer 可用性也随语义收口：find_spec 对 HCU 的 flashinfer 桩包恒
    # True，is_cuda()=True 后上游会信以为真并裸 import（token_dispatcher/
    # flashinfer_utils 无 except 兜底）。HCU 路线是 attention 走 fa3/triton，
    # flashinfer 恒不可用。
    def _hcu_fi_available():
        return False

    _common.is_flashinfer_available = _hcu_fi_available
    if _device is not None:  # v0.5.22: no utils/device module (review #98)
        _device.is_flashinfer_available = _hcu_fi_available
    from sglang.srt.utils import log_utils as _log_utils
    _log_utils.is_flashinfer_available = _hcu_fi_available

    original_memory_capacity = _common.get_nvgpu_memory_capacity

    def _hcu_get_memory_capacity():
        if torch.version.hip:
            from hcu_adapter.hip_metadata import minimum_memory_capacity

            return minimum_memory_capacity()
        return original_memory_capacity()

    _common.get_nvgpu_memory_capacity = _hcu_get_memory_capacity

    original_device_sm = _common.get_device_sm

    def _hcu_get_device_sm():
        if torch.version.hip and not torch.cuda.is_initialized():
            from hcu_adapter.hip_metadata import compute_capability

            major, minor = compute_capability()
            return major * 10 + minor
        return original_device_sm()

    _common.get_device_sm = _hcu_get_device_sm
    original_capability = _common.get_device_capability
    original_core_count = _common.get_device_core_count

    def _hcu_get_device_capability(device_id=0):
        if torch.version.hip and not torch.cuda.is_initialized():
            from hcu_adapter.hip_metadata import compute_capability

            return compute_capability(device_id)
        return original_capability(device_id)

    def _hcu_get_device_core_count(device_id=0):
        if torch.version.hip and not torch.cuda.is_initialized():
            from hcu_adapter.hip_metadata import multiprocessor_count

            return multiprocessor_count(device_id)
        return original_core_count(device_id)

    _common.get_device_capability = _hcu_get_device_capability
    _common.get_device_core_count = _hcu_get_device_core_count

    from hcu_adapter import lightop_metadata

    lightop_metadata.install()
    # Preserve the original eager-import order and cached hardware predicates.
    # The hardware queries change transport, not their values or cache timing.
    import functools
    import sglang.srt.utils as early_utils

    for name in ("is_hcu", "is_hcu_native_fp8_supported"):
        original = getattr(_common, name, None)
        if original is not None:
            raw = getattr(original, "__wrapped__", original)
            replacement = functools.lru_cache(maxsize=1)(
                lightop_metadata.rewrite_function(raw)
            )
            setattr(_common, name, replacement)
            setattr(early_utils, name, replacement)
    for name in ("get_device_sm", "get_device_capability", "get_device_core_count"):
        setattr(early_utils, name, getattr(_common, name))
    if hasattr(_common, "W8a8GetCacheJSON"):
        _common.W8a8GetCacheJSON._initialize = lightop_metadata.rewrite_function(
            _common.W8a8GetCacheJSON._initialize
        )

    # torch HIP graph 拒收 external event（"External events are disallowed in
    # rocm"）；上游 shared_read_event.make_external_event 以 is_cuda 判定后调
    # Event(external=True)。HCU 硬件真值= HIP 无此能力，把上游的构造口替换
    # 为普通 Event（语义降级：外部读端 fastpath 关闭，与 is_cuda()=False 时
    # 上游行为一致——返回 None 正是它自己的降级臂）。
    def _hcu_make_external_event(device_module):
        return None

    _common.is_cuda = _hcu_is_cuda
    _common.is_hip = _hcu_is_hip
    _common.is_cuda_alike = _hcu_is_cuda_alike
    _pf._is_cuda_available = _hcu_pf_cuda_available
    _pf._is_rocm_available = _hcu_pf_rocm_available

    # CUDA-版本特性门（is_ampere_with_cuda_12_3 / is_hopper_with_cuda_12_3 /
    # is_blackwell / is_sm100_supported / ...）：import 时已 lru_cache(
    # partial(_check_cuda_device_version,...)) 冻结，且原实现会拿
    # torch.version.cuda.split —— HCU 上是 None，直接 AttributeError。
    # 语义上这些门判定的是"NVIDIA 特定版本特性"，HCU 不该放行：统一 False，
    # 上游走保守回退路径。按 __wrapped__ 精确识别，未来新增探针自动覆盖。
    # common 之外，`sglang.srt.utils/__init__` 的 `from .common import *`
    # 冻结了同一批原对象，sglang main 的 kernels 在模块 import 时经包级
    # re-export 调用它们（fused_sigmoid_gating_recurrent ->
    # `_is_sm90 = is_sm90_supported()`，kda 后端链）——必须双命名空间替换。
    import sglang.srt.utils as _pkg_utils

    _gates = _replace_version_gates(_common, _pkg_utils)
    if _device is not None:  # v0.5.22: no utils/device module (review #98)
        _gates += _replace_version_gates(_device, _pkg_utils)
    if _gates:
        LOG.warning(
            "HCU adapter: %d CUDA version gates -> False (common + utils"
            " package namespaces; e.g. %s)",
            len(_gates),
            ", ".join(sorted(_gates)[:3]),
        )

    # gcn 架构探针（is_gfx950_supported / is_gfx1250_supported，@lru_cache 无
    # __wrapped__）：原实现走 torch.version.hip 真值分支后裸调
    # get_device_properties(0) ——卡分区可见性（HIP_VISIBLE_DEVICES=8..15）
    # 且 CUDA 尚未 init 的 sitecustomize 早期 import 顺序下直接
    # "No CUDA GPUs are available"。HCU 是 gfx93x，这些门恒 False。
    _install_gfx_probe_guard(_common)

    impls = {
        "sglang.srt.utils.common:get_device_capability": _hcu_get_device_capability,
        "sglang.srt.utils.common:get_device_core_count": _hcu_get_device_core_count,
        "sglang.srt.utils.common:get_device_sm": _hcu_get_device_sm,
        "sglang.srt.utils.common:get_nvgpu_memory_capacity": _hcu_get_memory_capacity,
        "sglang.srt.utils.common:is_cuda": _hcu_is_cuda,
        "sglang.srt.utils.common:is_hip": _hcu_is_hip,
        "sglang.srt.utils.common:is_cuda_alike": _hcu_is_cuda_alike,
        "sglang.srt.utils.common:is_flashinfer_available": _hcu_fi_available,
        "sglang.srt.platforms:_is_cuda_available": _hcu_pf_cuda_available,
        "sglang.srt.platforms:_is_rocm_available": _hcu_pf_rocm_available,
        "sglang.srt.model_executor.runner_utils.shared_read_event:make_external_event": _hcu_make_external_event,
    }
    for target in _TARGETS:
        registry.register(
            "platform_detect",
            impls[target],
            target=target,
            mechanism=registry.MECH_SEAM,
            detail=f"semantics={sem}",
        )

    # `sglang.srt.utils/__init__` does `from .common import *` when IT is
    # first imported -- which happens as a side effect of our very own
    # `from sglang.srt.utils import common` above. The package namespace
    # therefore still holds the ORIGINAL callables; sync them (same for any
    # other already-imported re-export layer). The lru_cache version gates
    # were already synced inside _replace_version_gates above; these are the
    # four hand-written seam symbols.
    _sync = {
        "get_device_capability": _hcu_get_device_capability,
        "get_device_core_count": _hcu_get_device_core_count,
        "get_device_sm": _hcu_get_device_sm,
        "get_nvgpu_memory_capacity": _hcu_get_memory_capacity,
        "is_cuda": _hcu_is_cuda,
        "is_hip": _hcu_is_hip,
        "is_cuda_alike": _hcu_is_cuda_alike,
        "is_flashinfer_available": _hcu_fi_available,
    }
    for _n, _fn in _sync.items():
        if _device is not None and hasattr(_device, _n):
            setattr(_device, _n, _fn)
        if getattr(_pkg_utils, _n, None) is not _fn:
            setattr(_pkg_utils, _n, _fn)

    # runner_utils imports DeepEP and quantization before shared_read_event.
    # Install both predicate namespaces and hardware guards before that import.
    try:
        from sglang.srt.model_executor.runner_utils import (
            shared_read_event as _sre,
        )

        _sre.make_external_event = _hcu_make_external_event
    except Exception:
        LOG.warning("HCU adapter: shared-read event seam not installed", exc_info=True)

    _rebind_stale_is_cuda(_hcu_is_cuda, registry)
    if torch.version.hip:
        _install_ar_hw_truth(registry)
    LOG.warning(
        "HCU adapter: platform semantics seam installed "
        "(sglang answers CUDA; hw layers stay HIP-truthful)"
    )

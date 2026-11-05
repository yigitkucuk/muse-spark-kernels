def _glue_context_api():
    global _GLUE_CONTEXT_API
    if _GLUE_CONTEXT_API is None:
        api = _C.CDLL("libcuda.so.1")
        for name, args in (
            ("cuCtxGetCurrent", [_C.POINTER(_C.c_void_p)]),
            ("cuCtxGetDevice", [_C.POINTER(_C.c_int)]),
            ("cuDeviceGet", [_C.POINTER(_C.c_int), _C.c_int]),
            ("cuDevicePrimaryCtxRetain", [_C.POINTER(_C.c_void_p), _C.c_int]),
            ("cuCtxSetCurrent", [_C.c_void_p]),
        ):
            function = getattr(api, name)
            function.argtypes, function.restype = args, _C.c_int
        _GLUE_CONTEXT_API = api
    return _GLUE_CONTEXT_API

def _glue_context_check(status, operation):
    if status:
        raise RuntimeError(f"{operation} failed with CUDA driver status {status}")

def _glue_bind_context(x):
    index = x.device.index if x.device.index is not None else 0
    if getattr(_GLUE_CONTEXT_TLS, "device", None) == index:
        return
    api = _glue_context_api()
    context = _C.c_void_p()
    _glue_context_check(api.cuCtxGetCurrent(_C.byref(context)), "cuCtxGetCurrent")
    current_device = _C.c_int(-1)
    if context.value:
        _glue_context_check(api.cuCtxGetDevice(_C.byref(current_device)), "cuCtxGetDevice")
    if not context.value or current_device.value != index:
        device, primary = _C.c_int(), _C.c_void_p()
        _glue_context_check(api.cuDeviceGet(_C.byref(device), index), "cuDeviceGet")
        _glue_context_check(api.cuDevicePrimaryCtxRetain(_C.byref(primary), device), "cuDevicePrimaryCtxRetain")
        _glue_context_check(api.cuCtxSetCurrent(primary), "cuCtxSetCurrent")
    _GLUE_CONTEXT_TLS.device = index

_glue_context_parent_kernel = kernel_fn
def kernel_fn(data, state):
    _glue_bind_context(data["attn_input"])
    return _glue_context_parent_kernel(data, state)


@triton.jit
def _router_input_norm(S1, G, OUT):
    t = tl.program_id(0)
    offs = tl.arange(0, 8192)
    s1 = tl.load(S1 + t * 8192 + offs)
    gw = 1.0 + tl.load(G + offs).to(tl.float32)
    hh = s1 * tl.rsqrt(tl.sum(s1 * s1, 0) / 8192.0 + 1e-5) * gw
    tl.store(OUT + t * 8192 + offs, hh)


def _pool_router_fp32(h, hr, T, state, ppick):
    if T <= 8:
        if state.get("bfp") is not None and ppick in ("bfp", "bfpf"):
            if ppick == "bfpf":
                _bfp_pdl(T, "pool")
            pooled = _bfp_gemm(state, "pool", h, T, D_EXPERT, HIDDEN)
        else:
            pooled = F.linear(h, state["pr"][:D_EXPERT])
        logits = _router_fp32_gemv(hr, state)
        return (pooled, logits), -1
    if ppick == "bfpf" and T <= 32 and state.get("bfp") is not None:
        _bfp_pdl(T, "pool")
        return bfp_fused_pooler_router(h, state["bfp"]), -1
    if ppick == "bfp" and state.get("bfp") is not None:
        pooled = _bfp_gemm(state, "pool", h, T, D_EXPERT, HIDDEN)
        logits = _bfp_gemm(state, "router", h, T, N_EXPERTS, HIDDEN)
        return (pooled, logits), -1
    return dense(h, state["pr"], T, state, "pr")


_tune_with_bias_restore = _tune


def _tune(st, log=False):
    bias0 = st["bias"].clone()
    try:
        return _tune_with_bias_restore(st, log=log)
    finally:
        st["bias"].copy_(bias0)


_moe_global_cache = _moe


class _RouterExt:
    def __init__(self, module):
        self._module = module

    def __getattr__(self, name):
        return getattr(self._module, name)

    def __deepcopy__(self, memo):
        return self


def _moe(M=None, state=None):
    if state is None:
        return _moe_global_cache(M)
    sfx = tuple(state["ma_sfx"])
    if M is not None and MOE_TINY_DEFINES and M <= MOE_TINY_MAX_M:
        key, defines = "tiny", MOE_TINY_DEFINES
    elif M is not None and MOE_TINY2_DEFINES and M <= MOE_TINY2_MAX_M and (sfx or "-DOKC_WGS=1" not in tuple(MOE_TINY2_DEFINES)):
        key, defines = "tiny2", MOE_TINY2_DEFINES
    elif M is not None and MOE_MID_DEFINES and M <= MOE_MID_MAX_M:
        key, defines = "mid", MOE_MID_DEFINES
    elif M is not None and 16 < M <= 32 and tuple(_main_defines(sfx)) == tuple(MOE_DEFINES):
        key, defines = "b4", tuple(MOE_DEFINES) + ("-DOKC_B4FIN=1",)
    else:
        key, defines = "main", _main_defines(sfx)
    ext = state["ma_ext"].get(key)
    if ext is None:
        ext = _RouterExt(_ma_ext(tuple(defines) + sfx))
        if MOE_HAS_PDL:
            ext.okc_set_pdl(0)
        state["ma_ext"][key] = ext
    return ext


_router_fp32_parent_prepare = prepare


def prepare(weights):
    st = _router_fp32_parent_prepare(weights)
    for T in (1, 8, 16, 32, 128, 256):
        _moe(T, st)
    return st


_ROUTER_FP32_CUDA = __cuda__("router_fp32.cu")
_ROUTER_FP32_EXT = None


def _router_fp32_ext():
    global _ROUTER_FP32_EXT
    if _ROUTER_FP32_EXT is None:
        import hashlib
        digest = hashlib.md5(_ROUTER_FP32_CUDA.encode()).hexdigest()[:12]
        cpp = '#include <pybind11/pybind11.h>\n#include <stdint.h>\nint router_fp32_launch(int64_t,int64_t,int64_t,int,int64_t);'
        _ROUTER_FP32_EXT = load_inline(
            name='router_fp32_' + digest,
            cpp_sources=cpp,
            cuda_sources=_ROUTER_FP32_CUDA,
            functions=['router_fp32_launch'],
            no_implicit_headers=True,
            with_pytorch_error_handling=False,
            verbose=False,
            extra_cuda_cflags=['-O3', '-gencode=arch=compute_90,code=sm_90'])
    return _ROUTER_FP32_EXT


def _router_fp32_gemv(x, state):
    m = x.shape[0]
    out = torch.empty((m, 256), dtype=torch.float32, device=x.device)
    rc = state['router_fp32_ext'].router_fp32_launch(
        x.data_ptr(), state['router_fp32'].data_ptr(), out.data_ptr(), m,
        torch.cuda.current_stream().cuda_stream)
    if rc:
        raise RuntimeError(f'FP32 router launch failed: {rc}')
    return out


_router_fp32_native_parent_prepare = prepare


def prepare(weights):
    state = _router_fp32_native_parent_prepare(weights)
    state['router_fp32_ext'] = _RouterExt(_router_fp32_ext())
    return state


_kfix_router_fp32_gemv = _router_fp32_gemv
def _router_fp32_gemv(x, state):
    if state.get('router_fp32_ext') is None:
        state['router_fp32_ext'] = _RouterExt(_router_fp32_ext())
    return _kfix_router_fp32_gemv(x, state)


GLE_T = {1: True}   # T = 8 keeps 0389's b1
GLE_FRT = True      # T <= 8: the fused pooler + FP32 router kernel (else 0389's split pooler / FP32 GEMV)
GLE_ILV = 1         # its 4 FP32 router stages interleave the pooler stream: 1 last slot of each period, 2 first slot after the PDL pre-issue, 0 off
GLE_CAPTURE = None   # diagnostics: a dict receives this call's pooler / router outputs and partials
GLE_RC = {1: 8}   # T -> NCH: NCH * T extra route programs (no wait) form the carry, 8192 / (NCH * T) columns x T tokens each
_GLE_EXT = None



"""V4-Flash 引擎 v3 — 三层缓存 (照 122B test_122b_fast.py / qwen_repo 基建)
- 非专家权重: 逐层 pread → RAM → 官方层 forward (单层放 GPU, 算完释放)
- 专家: PreadExpertReader 按需 pread 活性 top-6 + RAM LRU (OrderedDict), 不打包 3D
- forward 数学: attention/mHC/gate/shared 用官方 DeepseekV4DecoderLayer; 专家 FP8 GEMM 手写
  (参考官方 FP8Experts.forward 数学), 全程 fp32 激活
峰值: embed 1GB + 单层非专家 ~0.3GB + 活性专家 ~0.2GB ≈ 1.5GB GPU / <2GB CPU

【2026-08-17 魔改】添加分块注意力支持，根治长上下文 OOM
"""
import os, sys, json, struct, time, re, gc, threading, copy, ctypes
from concurrent.futures import ThreadPoolExecutor

# === 分块注意力补丁（在线分块 softmax，支持 1M 上下文）===
from v4flash_chunked_attention import apply_chunked_attention_patch, remove_chunked_attention_patch, CPUDynamicCache
# 低优先级运行 (照 122B), 避免抢占前台资源
try:
    ctypes.windll.kernel32.SetPriorityClass(ctypes.windll.kernel32.GetCurrentProcess(), 0x4000)
except Exception:
    pass
os.environ.setdefault('HF_HUB_OFFLINE', '1')
os.environ.setdefault('TRANSFORMERS_OFFLINE', '1')
import torch
import torch.nn.functional as F
from pathlib import Path
from collections import OrderedDict

# FP8 内核 (finegrained-fp8 v4, 本地缓存直接加载)
_KERNEL_DIR = Path(r'C:/Users/<user>/.cache/huggingface/hub/kernels--kernels-community--finegrained-fp8/snapshots/7cdb05d472d6c954c7d03182ed836ebfd4610df0/build/torch-cuda')

def _load_fp8_kernel():
    import importlib.util
    spec = importlib.util.spec_from_file_location(
        '_fp8_kernel', _KERNEL_DIR / '__init__.py', submodule_search_locations=[str(_KERNEL_DIR)])
    mod = importlib.util.module_from_spec(spec)
    sys.modules['_fp8_kernel'] = mod
    spec.loader.exec_module(mod)
    return mod

# ═══ ROCm 兼容层 (2026-09-12) ═══
# gfx1100 (RDNA3) 没有 FP8 矩阵乘硬件 (torch._scaled_mm 未实现), 且
# kernels-community/finegrained-fp8 只有 torch-cuda 构建 → 加载必失败。
# 解法: 纯 PyTorch 复现同样的数学 (反量化到 x.dtype 再 matmul), 实测 3.9ms/层。
#   V4F_TORCH_FP8=1 强制纯 PyTorch; kernel 加载失败时也会自动回退。
_USE_TORCH_FP8 = os.environ.get('V4F_TORCH_FP8', '') == '1'
_RESIDENT_LAYERS = os.environ.get('V4F_RESIDENT_LAYERS', '0') == '1'

FP8_KERNEL = None
if not _USE_TORCH_FP8:
    try:
        FP8_KERNEL = _load_fp8_kernel()
    except Exception as _e:
        print(f'[fp8] CUDA kernel 不可用 ({str(_e)[:90]}) -> 回退纯 PyTorch 反量化', flush=True)
        _USE_TORCH_FP8 = True
import transformers.integrations.finegrained_fp8 as _ff8
if FP8_KERNEL is not None:
    _ff8.lazy_load_kernel = lambda *a, **k: FP8_KERNEL


if FP8_KERNEL is None:
    # ROCm: transformers 5.16.x 的 FP8Linear/FP8GroupedLinear 全走 CUDA kernel
    # (load_finegrained_fp8_kernel) -> 统一换成纯 PyTorch 实现
    def _dequant_linear(x, w, scale_inv, block_size, out_dtype=None):
        N, K = w.shape
        bn, bk = int(block_size[0]), int(block_size[1])
        dt = x.dtype
        ww = w.to(dt)
        ss = scale_inv.to(dt)
        if N % bn == 0 and K % bk == 0:
            ww = (ww.view(N // bn, bn, K // bk, bk) * ss.view(N // bn, 1, K // bk, 1)).view(N, K)
        else:
            ww = ww * ss.repeat_interleave(bn, 0).repeat_interleave(bk, 1)[:N, :K]
        return torch.nn.functional.linear(x, ww)

    class _TorchFP8Kernel:
        """纯 PyTorch 复刻 finegrained-fp8 kernel (ROCm 无 Triton/CUDA kernel)"""
        @staticmethod
        def matmul(x, w, scale_inv, block_size, out_dtype=None, activation_scale=None):
            return _dequant_linear(x, w, scale_inv, block_size, out_dtype or x.dtype)

        @staticmethod
        def grouped_matmul(x, w, scale_inv, offsets=None, tokens_per_expert=None, block_size=None):
            G, N, K = w.shape
            if offsets is None:
                tok = x.shape[0] // G
                offs = [i * tok for i in range(G + 1)]
            else:
                offs = [0] + [int(o) for o in offsets]
            out = torch.empty(x.shape[0], N, dtype=x.dtype, device=x.device)
            bs = block_size if block_size is not None else (128, 128)
            for g in range(G):
                s0, s1 = offs[g], offs[g + 1]
                if s1 > s0:
                    out[s0:s1] = _dequant_linear(x[s0:s1], w[g], scale_inv[g], bs, x.dtype)
            return out

    _ff8.load_finegrained_fp8_kernel = lambda: _TorchFP8Kernel
    if hasattr(_ff8, "lazy_load_kernel"):
        _ff8.lazy_load_kernel = lambda *a, **k: _TorchFP8Kernel
    print("[rocm] finegrained_fp8 kernel -> 纯 PyTorch (matmul+grouped_matmul)", flush=True)


# ═══ NaN 探针 (诊断用, V4F_NAN_PROBE=1 开启) ═══
_NAN_PROBE = os.environ.get('V4F_NAN_PROBE', '0') == '1'


_NAN_LAYERS = set(int(x) for x in os.environ.get('V4F_NAN_LAYERS', '22,23,24,25').split(',') if x.strip())


def _register_nan_hooks(layer, lid):
    """给该层所有子模块挂 forward hook: 输出非有限时打印模块名 + 输入是否已经非有限"""
    if getattr(layer, '_nan_hooked', False):
        return
    layer._nan_hooked = True

    def _mk(_name, _l):
        def _hook(mod, inp, out):
            t = out[0] if isinstance(out, (tuple, list)) and out else out
            if not torch.is_tensor(t):
                return
            try:
                bad = int((~torch.isfinite(t)).sum())
            except Exception:
                return
            if bad == 0:
                return
            in_bad = False
            for _i in inp:
                if torch.is_tensor(_i):
                    try:
                        if int((~torch.isfinite(_i)).sum()):
                            in_bad = True
                            break
                    except Exception:
                        pass
            print(f'[nanhook] L{_l} {_name} out_bad={bad}/{t.numel()} in_bad={in_bad}', flush=True)
        return _hook

    for _name, _m in layer.named_modules():
        if _m is layer:
            continue
        _m.register_forward_hook(_mk(_name, lid))


def _rope_dump(layers, tag):
    """打印各层 compressor.rotary_emb 的 inv_freq 缓冲状态 (NaN 计数 + 值)"""
    out = []
    for _lid, _l in enumerate(layers):
        _re = None
        for _n, _m in _l.named_modules():
            if _n.endswith('compressor.rotary_emb'):
                _re = _m
                break
        if _re is None:
            continue
        _info = []
        for _bn, _b in _re.named_buffers():
            if 'inv_freq' in _bn:
                try:
                    _bad = int((~torch.isfinite(_b)).sum())
                except Exception:
                    _bad = -1
                _info.append('%s=%d/%d(%s)' % (_bn, _bad, _b.numel(), _b.device.type))
        if _info:
            out.append('L%d[%s]' % (_lid, ' '.join(_info)))
            if any(('=%d/32' % 32) not in x and '=0/' not in x for x in _info):
                for _bn, _b in _re.named_buffers():
                    if 'inv_freq' in _bn:
                        try:
                            print('[ropedump:%s] L%d %s 值=%s' % (
                                tag, _lid, _bn,
                                [round(float(x), 5) for x in _b.cpu().flatten()[:32]]), flush=True)
                        except Exception:
                            pass
    print('[ropedump:%s] %s' % (tag, ' '.join(out)), flush=True)
    _b3 = [b for n, b in layers[3].named_buffers() if 'inv_freq' in n] if 3 in layers else []
    for _b in _b3:
        try:
            print('[ropedump:%s] L3 值=%s' % (tag, [round(float(x), 4) for x in _b.cpu().flatten()[:32]]), flush=True)
        except Exception as _e:
            print('[ropedump:%s] L3 读值失败 %s' % (tag, _e), flush=True)



def _rope_watch(layers, tag):
    """打印已被写入 NaN 的 rope inv_freq 缓冲 (canary), 无命中打印 clean"""
    if not _NAN_PROBE:
        return
    bad = []
    for _lid, _l in enumerate(layers):
        try:
            for _n, _m in _l.named_modules():
                if _n.endswith('compressor.rotary_emb'):
                    for _bn, _b in _m.named_buffers():
                        if 'inv_freq' in _bn:
                            try:
                                _k = int((~torch.isfinite(_b)).sum())
                            except Exception:
                                _k = -1
                            if _k:
                                bad.append('%d.%s=%d/%d' % (_lid, _bn.split("_")[0], _k, _b.numel()))
                    break
        except Exception:
            pass
    print('[ropewatch] %-14s %s' % (tag, (' '.join(bad) if bad else 'clean')), flush=True)



def _nan_check(t, tag):
    """非有限值检查: 只在命中时打印, 附位置索引 (探针, 不参与计算)"""
    if not _NAN_PROBE:
        return
    try:
        mask = ~torch.isfinite(t)
        n = int(mask.sum())
    except Exception:
        return
    if n == 0:
        return
    fin = t[~mask]
    mx = float(fin.abs().max()) if fin.numel() else float('nan')
    pos = mask.nonzero()[:4].tolist()
    print(f'[nanprobe] {tag}: 非有限 {n}/{t.numel()} max|fin|={mx:.3e} dtype={t.dtype} pos={pos}', flush=True)



def _dequant_matmul(x, w_fp8, scale, block, out_dtype=torch.bfloat16):
    """纯 PyTorch 版: dequant(w) = w_fp8 * scale → x @ w^T"""
    bn, bk = block[0], block[1]
    s = scale.repeat_interleave(bn, 0).repeat_interleave(bk, 1).to(x.dtype)
    w = w_fp8.to(x.dtype) * s
    return x @ w.t()


# ═══ Triton 融合 MXFP4 算子 + 分组 MoE (2026-09-15) ═══
# 动机(实测): 物化路径 _dequant_mxfp4 每次 GEMM 0.93 ms (要造 int64 索引+16MB bf16),
#             融合算子 0.17 ms (5.4x), 数值逐位一致; 逐专家循环的索引记账 70 ms/token
#             而分组版只要 2 ms/token (34x)。
_TRITON_FP4 = os.environ.get('V4F_TRITON_FP4', '0') == '1'
_GROUPED_MOE = os.environ.get('V4F_GROUPED_MOE', '0') == '1'
_HAS_TRITON = False
_TRITON_READY = {'ok': False, 'err': ''}
try:
    import triton as _triton
    import triton.language as _tl
    _HAS_TRITON = True
except Exception as _e:
    _TRITON_FP4 = False
    print('[triton] 不可用: %s' % str(_e)[:120], flush=True)

if _HAS_TRITON:
    @_triton.jit
    def _e2m1_val(nib):
        """4bit E2M1 (uint8 0..15) → float32"""
        n = nib.to(_tl.int32)
        e = (n >> 1) & 3
        m = (n & 1).to(_tl.float32)
        mag = _tl.where(e == 0, 0.5 * m,
                        _tl.exp2((e - 1).to(_tl.float32)) * (1.0 + 0.5 * m))
        return _tl.where(n >= 8, -mag, mag)

    @_triton.jit
    def _mxfp4_mm_kernel(x_ptr, w_ptr, s_ptr, y_ptr, M, N, K,
                         BLOCK_M: _tl.constexpr, BLOCK_N: _tl.constexpr, BLOCK_K: _tl.constexpr):
        pid_n = _tl.program_id(0)
        pid_m = _tl.program_id(1)
        offs_n = pid_n * BLOCK_N + _tl.arange(0, BLOCK_N)
        offs_m = pid_m * BLOCK_M + _tl.arange(0, BLOCK_M)
        KP: _tl.constexpr = BLOCK_K // 2
        SP: _tl.constexpr = BLOCK_K // 32
        acc = _tl.zeros((BLOCK_M, BLOCK_N), dtype=_tl.float32)
        for k0 in range(0, K, BLOCK_K):
            kb = (k0 // 2) + _tl.arange(0, KP)
            wb = _tl.load(w_ptr + offs_n[:, None] * (K // 2) + kb[None, :])
            u8 = wb.to(_tl.uint8, bitcast=True)
            low = _e2m1_val(u8 & 0x0F)
            high = _e2m1_val((u8 >> 4) & 0x0F)
            sb = _tl.load(s_ptr + offs_n[:, None] * (K // 32) + (k0 // 32) + _tl.arange(0, SP)[None, :])
            s32 = sb.to(_tl.uint8, bitcast=True).to(_tl.int32) << 23
            sf = _tl.reshape(_tl.broadcast_to(s32.to(_tl.float32, bitcast=True)[:, :, None],
                                              (BLOCK_N, SP, 16)), (BLOCK_N, KP))
            kk = k0 + _tl.arange(0, BLOCK_K)
            x = _tl.load(x_ptr + offs_m[:, None] * K + kk[None, :],
                         mask=(offs_m[:, None] < M), other=0.0)
            xe, xo = _tl.split(_tl.reshape(x, (BLOCK_M, KP, 2)))
            acc += _tl.sum((low * sf)[None, :, :] * xe[:, None, :], axis=2)
            acc += _tl.sum((high * sf)[None, :, :] * xo[:, None, :], axis=2)
        _tl.store(y_ptr + offs_m[:, None] * N + offs_n[None, :], acc.to(_tl.bfloat16),
                  mask=(offs_m[:, None] < M))


def _triton_mxfp4_matmul(x, w, s, out_dtype=torch.bfloat16):
    """x[M,K] @ dequant(w[N,K/2 int8 packed]).T  —— 融合算子, 解码 M 小"""
    M = x.shape[0]
    N, Kb = w.shape
    K = Kb * 2
    y = torch.empty(M, N, dtype=torch.bfloat16, device=x.device)
    grid = (_triton.cdiv(N, 32), _triton.cdiv(M, 1))
    _mxfp4_mm_kernel[grid](x, w, s.view(torch.uint8), y, M, N, K,
                           BLOCK_M=1, BLOCK_N=32, BLOCK_K=256, num_warps=8, num_stages=2)
    return y


def warmup_triton_kernels():
    """启动时后台把内核编译好 (否则首个用户请求要卡几分钟)"""
    if not (_TRITON_FP4 and _HAS_TRITON):
        return
    try:
        t0 = time.time()
        for (N, Kb) in ((2048, 2048), (4096, 1024)):
            w = torch.zeros(N, Kb, dtype=torch.int8, device='cuda')
            sc = torch.zeros(N, Kb // 16, dtype=torch.uint8, device='cuda')
            xb = torch.zeros(1, Kb * 2, dtype=torch.bfloat16, device='cuda')
            _triton_mxfp4_matmul(xb, w, sc, torch.bfloat16)
            xf = torch.zeros(1, Kb * 2, dtype=torch.float32, device='cuda')
            _triton_mxfp4_matmul(xf, w, sc, torch.bfloat16)
            torch.cuda.synchronize()
        _TRITON_READY['ok'] = True
        print('[triton] 内核预热完成 %.0fs' % (time.time() - t0), flush=True)
    except Exception as e:
        _TRITON_READY['err'] = str(e)[:200]
        print('[triton] 预热失败: %s' % str(e)[:200], flush=True)


_E2M1_LUT = None


def _dequant_mxfp4(x, w_i8, scale, out_dtype=torch.bfloat16):
    """纯 PyTorch MXFP4 (照官方 transformers/integrations/mxfp4.py):
    w   int8 [N, K//2]   packed E2M1 (每字节2个4bit浮点, 低nibble=偶数列)
    sc  UE8M0 [N, K//32] 解码 2^(exp-127)
    """
    global _E2M1_LUT
    if _E2M1_LUT is None or _E2M1_LUT.device != w_i8.device:
        _E2M1_LUT = torch.tensor(
            [0.0, 0.5, 1.0, 1.5, 2.0, 3.0, 4.0, 6.0,
             -0.0, -0.5, -1.0, -1.5, -2.0, -3.0, -4.0, -6.0],
            dtype=torch.float32, device=w_i8.device)
    u8 = w_i8.view(torch.uint8)
    lo = _E2M1_LUT[(u8 & 0x0F).long()]
    hi = _E2M1_LUT[(u8 >> 4).long()]
    N, Kb = w_i8.shape
    w = torch.empty(N, Kb * 2, dtype=torch.float32, device=w_i8.device)
    w[:, 0::2] = lo
    w[:, 1::2] = hi
    exp = scale.view(torch.uint8).to(torch.int32)
    s = (exp << 23).view(torch.float32).repeat_interleave(32, dim=1)
    return x @ (w * s).to(x.dtype).t()


def fp8_matmul(x, w, s, block, out_dtype=torch.bfloat16):
    """统一入口: int8->MXFP4 融合算子(可用时); 其余按 V4F_TORCH_FP8 选"""
    if w.dtype == torch.int8:
        if _TRITON_FP4 and _HAS_TRITON and _TRITON_READY['ok'] and x.shape[0] <= 8:
            return _triton_mxfp4_matmul(x, w, s, out_dtype)
        return _dequant_mxfp4(x, w, s, out_dtype)
    if _USE_TORCH_FP8:
        return _dequant_matmul(x, w, s, block, out_dtype)
    return FP8_KERNEL.matmul_2d(x, w, s, block, out_dtype)

MODEL_DIR = Path(os.environ.get('V4F_MODEL_DIR', r'D:\ai_v4flash'))
DEVICE = 'cuda'
BLOCK_SIZE = 128
DTYPE_MAP = {'F8_E4M3': torch.float8_e4m3fn, 'F8_E8M0': torch.float8_e8m0fnu, 'BF16': torch.bfloat16,
             'F32': torch.float32, 'F16': torch.float16, 'I8': torch.int8, 'I64': torch.int64}


# ═══ pread 基础 (绕开 mmap) ═══
def _load_disk_index():
    idx = json.load(open(MODEL_DIR / 'model.safetensors.index.json'))
    return idx['weight_map']

DISK = _load_disk_index()

def pread(key: str) -> torch.Tensor:
    shard = DISK[key]
    with open(MODEL_DIR / shard, 'rb') as f:
        hs = struct.unpack('<Q', f.read(8))[0]
        hdr = json.loads(f.read(hs))
        base = 8 + hs
        m = hdr[key]
        o0, o1 = m['data_offsets']
        f.seek(base + o0)
        data = f.read(o1 - o0)
        return torch.frombuffer(data, dtype=DTYPE_MAP[m['dtype']]).reshape(m['shape']).clone()


# ═══ key 转换 (非专家; 照 transformers conversion_mapping.py deepseek_v4) ═══
RENAME_RULES = [
    (r'\.scale$', r'.weight_scale_inv'),
    (r'\.attn\.', r'.self_attn.'),
    (r'\.ffn\.', r'.mlp.'),
    (r'\.indexer\.compressor\.', r'.compressor.indexer.'),
    (r'^embed\.weight$', 'embed_tokens.weight'),
    (r'^head\.weight$', 'lm_head.weight'),
    (r'^hc_head_fn$', 'hc_head.hc_fn'),
    (r'^hc_head_base$', 'hc_head.hc_base'),
    (r'^hc_head_scale$', 'hc_head.hc_scale'),
    (r'\.attn_norm\.', r'.input_layernorm.'),
    (r'\.ffn_norm\.', r'.post_attention_layernorm.'),
    (r'\.hc_attn_fn$', r'.attn_hc.fn'),
    (r'\.hc_attn_base$', r'.attn_hc.base'),
    (r'\.hc_attn_scale$', r'.attn_hc.scale'),
    (r'\.hc_ffn_fn$', r'.ffn_hc.fn'),
    (r'\.hc_ffn_base$', r'.ffn_hc.base'),
    (r'\.hc_ffn_scale$', r'.ffn_hc.scale'),
    (r'\.attn_sink$', r'.sinks'),
    (r'\.indexer\.weights_proj\.', r'.compressor.indexer.scorer.weights_proj.'),
    (r'\.indexer\.wq_b\.', r'.compressor.indexer.q_b_proj.'),
    (r'\.norm\.', r'.kv_norm.'),
    (r'\.ape$', r'.position_bias'),
    (r'\.wq_a\.', r'.q_a_proj.'),
    (r'\.self_attn\.wq_b\.', r'.self_attn.q_b_proj.'),
    (r'\.wkv\.', r'.kv_proj.'),
    (r'\.wgate\.', r'.gate_proj.'),
    (r'\.wo_a\.', r'.o_a_proj.'),
    (r'\.wo_b\.', r'.o_b_proj.'),
    (r'\.q_norm\.', r'.q_a_norm.'),
    (r'\.gate\.bias$', r'.gate.e_score_correction_bias'),
    (r'\.shared_experts\.w1\.', r'.shared_experts.gate_proj.'),
    (r'\.shared_experts\.w2\.', r'.shared_experts.down_proj.'),
    (r'\.shared_experts\.w3\.', r'.shared_experts.up_proj.'),
]

def rename_key(k: str) -> str:
    for pat, rep in RENAME_RULES:
        k = re.sub(pat, rep, k)
    return k

# ═══ RoPE buffer 修复 (2026-09-13) ═══
# 根因: _build_template/V4MTPModule 里的 to_empty(device='cpu') 把 persistent=False 的
# buffer 重建为「未初始化内存」, 而 load_state_dict 的 state_dict 不含这些 key
# → RoPE 的 *_inv_freq / *_original_inv_freq 会带着上一手内存数据上线。
# 云端该内存常含 NaN 位模式(FP8 权重读盘留下的 0xFF) → 该层 hidden 全 NaN;
# 本地拿到的是干净页 → 只表现为频率静默失效(值≈0), 不报错。
_ROPE_FIX = {'n_mod': 0, 'n_buf': 0, 'n_bad_before': 0, 'n_bad_after': 0}


def _verify_rope_all(engine_rope, layers, tag=''):
    """按属性逐位比对所有 rope 模块的 inv_freq, 并统计覆盖面"""
    try:
        from transformers.models.deepseek_v4.modeling_deepseek_v4 import DeepseekV4RotaryEmbedding
    except Exception as _e:
        print('[ropeverify] 导入失败', _e, flush=True)
        return
    ref = {}
    for _lt in getattr(engine_rope, 'layer_types', []):
        _b = getattr(engine_rope, '%s_inv_freq' % _lt, None)
        if _b is not None:
            ref[_lt] = _b.detach().cpu().float()
    n_mod = n_buf = n_ok = n_bad = n_nan = 0
    mod_layers = []
    bad = []
    for _lid, _l in enumerate(layers):
        _found = False
        for _mn, _m in _l.named_modules():
            if not isinstance(_m, DeepseekV4RotaryEmbedding):
                continue
            _found = True
            n_mod += 1
            for _lt in getattr(_m, 'layer_types', []):
                for _sfx in ('_inv_freq', '_original_inv_freq'):
                    _b = getattr(_m, '%s%s' % (_lt, _sfx), None)
                    if _b is None or _lt not in ref:
                        continue
                    n_buf += 1
                    _v = _b.detach().cpu().float()
                    if int((~torch.isfinite(_v)).sum()):
                        n_nan += 1
                    if _v.shape == ref[_lt].shape and bool(torch.equal(_v, ref[_lt])):
                        n_ok += 1
                    else:
                        n_bad += 1
                        if len(bad) < 6:
                            bad.append('%d:%s%s ref0=%.5f got0=%.5f' % (
                                _lid, _lt, _sfx, float(ref[_lt][0]), float(_v[0])))
        if _found:
            mod_layers.append(_lid)
    print('[ropeverify:%s] rope模块=%d 缓冲=%d 逐位一致=%d 不一致=%d 含NaN=%d' % (
        tag, n_mod, n_buf, n_ok, n_bad, n_nan), flush=True)
    print('[ropeverify:%s] 含 rope 模块的层: %s' % (tag, mod_layers), flush=True)
    if bad:
        print('[ropeverify:%s] 不一致样例: %s' % (tag, bad), flush=True)


def _reinit_rope_buffers(mod, tag=''):
    """照官方 transformers `_init_weights` 的 DeepseekV4RotaryEmbedding 分支重算 inv_freq。"""
    try:
        from transformers.models.deepseek_v4.modeling_deepseek_v4 import DeepseekV4RotaryEmbedding
        try:
            from transformers.modeling_rope_utils import ROPE_INIT_FUNCTIONS
        except Exception:
            from transformers.models.deepseek_v4.modeling_deepseek_v4 import ROPE_INIT_FUNCTIONS
    except Exception as _e:
        print('[ropefix] 导入失败, 跳过:', _e, flush=True)
        return
    _ROPE_FIX['n_mod'] += 1
    for _m in mod.modules():
        if not isinstance(_m, DeepseekV4RotaryEmbedding):
            continue
        for _lt in getattr(_m, 'layer_types', []):
            _b = getattr(_m, f'{_lt}_inv_freq', None)
            if _b is None:
                continue
            _bo = getattr(_m, f'{_lt}_original_inv_freq', None)
            try:
                if int((~torch.isfinite(_b)).sum()) or (_bo is not None and int((~torch.isfinite(_bo)).sum())):
                    _ROPE_FIX['n_bad_before'] += 1
            except Exception:
                pass
            _rt = (getattr(_m, 'rope_type', None) or {}).get(_lt, 'default')
            _fn = _m.compute_default_rope_parameters if _rt == 'default' else ROPE_INIT_FUNCTIONS[_rt]
            _inv, _ = _fn(_m.config, layer_type=_lt)
            with torch.no_grad():
                _b.copy_(_inv.to(device=_b.device, dtype=_b.dtype))
                if _bo is not None:
                    _bo.copy_(_inv.to(device=_bo.device, dtype=_bo.dtype))
            _ROPE_FIX['n_buf'] += 1
            try:
                if int((~torch.isfinite(_b)).sum()):
                    _ROPE_FIX['n_bad_after'] += 1
            except Exception:
                pass
    # 体检: 小张量里还有没有非有限值 (其它未初始化 buffer 的话能立刻发现)
    _bad = []
    for _n, _t in list(mod.named_parameters()) + list(mod.named_buffers()):
        try:
            if _t.numel() <= 65536 and int((~torch.isfinite(_t)).sum()):
                _bad.append(_n)
        except Exception:
            pass
    if _bad:
        print('[ropefix] %s 仍有非有限小张量: %s' % (tag, _bad[:8]), flush=True)



def convert_layer_sd(raw_sd: dict) -> dict:
    """非专家权重 dict (完整 key 含 layers.N. 前缀) → 官方参数名 state_dict"""
    renamed = {rename_key(k): v for k, v in raw_sd.items()}
    return {re.sub(r'^layers\.\d+\.', '', k): v for k, v in renamed.items()}


# ═══ 专家按需读取 + RAM LRU (照 122B exp_cache / qwen_repo SafeExpertReader) ═══
class ExpertReader:
    """按需 pread 单个专家 (V4 独立 w1/w2/w3 + scale, FP8)"""
    def __init__(self, model_dir: Path, disk_index: dict):
        self.model_dir = model_dir
        self.disk = disk_index
        self._remaps = {}       # shard -> 替代路径 (C 盘双盘并发)
        self._hdr_cache = {}
        self._tl = threading.local()

    def remap(self, shard: str, newpath: str):
        """把 shard 重映射到其他盘 (双盘并发)"""
        self._remaps[shard] = newpath
        self._hdr_cache.pop(shard, None)

    def layer_shard(self, lid: int) -> str:
        """层 lid 的专家所在 shard 名"""
        return self.disk[f'layers.{lid}.ffn.experts.0.w1.weight']

    def on_c(self, shard: str) -> bool:
        """该 shard 是否已 remap 到 C 盘"""
        return shard in self._remaps

    def _shard_path(self, shard: str) -> Path:
        return Path(self._remaps[shard]) if shard in self._remaps else self.model_dir / shard

    def _fh(self, shard: str):
        hs = getattr(self._tl, 'h', None)
        if hs is None:
            hs = {}
            self._tl.h = hs
        if shard not in hs:
            hs[shard] = open(self._shard_path(shard), 'rb')
        return hs[shard]

    def _read(self, key: str) -> torch.Tensor:
        shard = self.disk[key]
        f = self._fh(shard)
        # header 缓存 (per-thread)
        hd = self._hdr_cache.get(shard)
        if hd is None:
            with open(self._shard_path(shard), 'rb') as tf:
                n = struct.unpack('<Q', tf.read(8))[0]
                hd = (n + 8, json.loads(tf.read(n)))
            self._hdr_cache[shard] = hd
        base, hdr = hd
        m = hdr[key]
        o0, o1 = m['data_offsets']
        f.seek(base + o0)
        data = f.read(o1 - o0)
        return torch.frombuffer(data, dtype=DTYPE_MAP[m['dtype']]).reshape(m['shape']).clone()

    def read_expert(self, lid: int, eid: int):
        """返回 w1,s1,w2,s2,w3,s3 (CPU)"""
        p = f'layers.{lid}.ffn.experts.{eid}'
        return (self._read(f'{p}.w1.weight'), self._read(f'{p}.w1.scale'),
                self._read(f'{p}.w2.weight'), self._read(f'{p}.w2.scale'),
                self._read(f'{p}.w3.weight'), self._read(f'{p}.w3.scale'))


class ExpertLRU:
    """RAM LRU 专家缓存 (照 122B): 命中直接上 GPU, miss 读盘"""
    def __init__(self, reader: ExpertReader, max_items: int = 650, device=DEVICE):
        self.reader = reader
        self.cache: OrderedDict = OrderedDict()
        self.max = max_items
        self.device = device
        self.lock = threading.Lock()
        self.hits = [0]
        self.miss = [0]

    def get(self, lid: int, eid: int):
        key = (lid, eid)
        with self.lock:
            hit = self.cache.get(key)
            if hit is not None:
                self.cache.move_to_end(key)
                self.hits[0] += 1
                return hit
        t = self.reader.read_expert(lid, eid)
        with self.lock:
            self.miss[0] += 1
            self.cache[key] = t
            while len(self.cache) > self.max:
                self.cache.popitem(last=False)
        return t


# ═══ 按需专家 MoE (参考官方 FP8Experts.forward 数学, 专家从 LRU 取) ═══
class V4LazyMoE(torch.nn.Module):
    def __init__(self, config, lid: int, engine, mtp: bool = False):
        super().__init__()
        from transformers.models.deepseek_v4.modeling_deepseek_v4 import (
            DeepseekV4TopKRouter, DeepseekV4HashRouter, DeepseekV4MLP)
        self.config = config
        self.lid = lid
        self.engine = engine
        self.mtp = mtp
        if mtp:
            self.is_hash = False   # MTP gate 是 TopKRouter (有 e_score_correction_bias, 无 tid2eid)
        else:
            self.is_hash = config.mlp_layer_types[lid] == 'hash_moe'
        self.gate = DeepseekV4HashRouter(config) if self.is_hash else DeepseekV4TopKRouter(config)
        self.shared_experts = DeepseekV4MLP(config)
        self.top_k = config.num_experts_per_tok
        self.limit = config.swiglu_limit

    def _forward_grouped(self, hidden_states: torch.Tensor, input_ids: torch.Tensor | None = None) -> torch.Tensor:
        """分组版 MoE (2026-09-15): 一次摊开路由 → 按专家分组 → 逐组算 → 一次散射
        实测: 索引记账 70.3 → 2.1 ms/token (34x); 配合融合 FP4 内核 GEMM 0.93 → 0.17 ms"""
        B, S, H = hidden_states.shape
        residual = hidden_states
        flat = hidden_states.reshape(-1, H)
        if self.is_hash:
            _, weights, indices = self.gate(hidden_states, input_ids)
        else:
            _, weights, indices = self.gate(hidden_states)
        _tm0 = time.perf_counter()
        idx_cpu = indices.tolist()          # 全层唯一一次 GPU→CPU 同步
        w_cpu = weights.tolist()
        T = flat.shape[0]
        K = indices.shape[-1]
        triples = []
        for r in range(T):
            row, wrow = idx_cpu[r], w_cpu[r]
            for s_i in range(K):
                triples.append((row[s_i], r, wrow[s_i]))
        triples.sort(key=lambda x: x[0])
        rows_all = torch.tensor([t[1] for t in triples], device=flat.device, dtype=torch.long)
        wts_all = torch.tensor([t[2] for t in triples], device=flat.device, dtype=torch.float32)
        x_all = flat.index_select(0, rows_all)          # 一次 gather
        groups = []
        i = 0
        n = len(triples)
        while i < n:
            j = i
            while j < n and triples[j][0] == triples[i][0]:
                j += 1
            groups.append((triples[i][0], i, j))
            i = j
        uids = [g[0] for g in groups]
        if self.mtp:
            futs = {eid: self.engine.expert_pool.submit(self.engine.get_mtp_expert, eid) for eid in uids}
        else:
            futs = {eid: self.engine.expert_pool.submit(self.engine.get_expert, self.lid, eid) for eid in uids}
        out_flat = torch.zeros(T * K, H, device=flat.device, dtype=torch.float32)
        for (eid, o0, o1) in groups:
            w1, s1, w2, s2, w3, s3 = futs[eid].result()
            x = x_all[o0:o1]
            _nan_check(x, f'moe{self.lid} in')
            g = fp8_matmul(x, w1, s1, [BLOCK_SIZE, BLOCK_SIZE], torch.bfloat16).float()
            u = fp8_matmul(x, w3, s3, [BLOCK_SIZE, BLOCK_SIZE], torch.bfloat16).float()
            gate = g.clamp(max=self.limit)
            up = u.clamp(min=-self.limit, max=self.limit)
            inter = torch.nn.functional.silu(gate) * up
            d = fp8_matmul(inter, w2, s2, [BLOCK_SIZE, BLOCK_SIZE], torch.bfloat16).float()
            out_flat[o0:o1] = d * wts_all[o0:o1].unsqueeze(-1)
        out = torch.zeros(T, H, device=flat.device, dtype=torch.float32)
        out.index_add_(0, rows_all, out_flat)           # 一次散射
        _nan_check(out, f'moe{self.lid} out')
        shared = self.shared_experts(residual).to(torch.float32)
        _nan_check(shared, f'moe{self.lid} shared')
        self.engine._tm['moe'] = self.engine._tm.get('moe', 0.0) + (time.perf_counter() - _tm0)
        return (out.view(B, S, H) + shared).to(hidden_states.dtype)

    def forward(self, hidden_states: torch.Tensor, input_ids: torch.Tensor | None = None) -> torch.Tensor:
        if _GROUPED_MOE:
            try:
                return self._forward_grouped(hidden_states, input_ids)
            except Exception as _e:
                globals()['_GROUPED_MOE'] = False
                print('[grouped] 失败, 回落原路径: %s' % str(_e)[:200], flush=True)
        from transformers.models.deepseek_v4.modeling_deepseek_v4 import ACT2FN
        if self.engine._dbg_dtype is not None:
            print(f'[dbg] V4LazyMoE.l{self.lid} in={hidden_states.dtype}', flush=True)
        B, S, H = hidden_states.shape
        residual = hidden_states
        flat = hidden_states.reshape(-1, H)
        if self.is_hash:
            _, weights, indices = self.gate(hidden_states, input_ids)
        else:
            _, weights, indices = self.gate(hidden_states)

        uids = indices.unique().tolist()
        # 并行: 活性专家并发读取 (MTP 走 mtp.0 路径)
        if self.mtp:
            futs = {eid: self.engine.expert_pool.submit(self.engine.get_mtp_expert, eid) for eid in uids}
        else:
            futs = {eid: self.engine.expert_pool.submit(self.engine.get_expert, self.lid, eid) for eid in uids}
        out = torch.zeros(flat.shape[0], H, device=flat.device, dtype=torch.float32)
        for eid in uids:
            w1, s1, w2, s2, w3, s3 = futs[eid].result()
            hit_2d = (indices == eid)              # [B*S, top_k]
            tidx = hit_2d.any(-1).nonzero().squeeze(-1)
            if tidx.numel() == 0:
                continue
            x = flat[tidx]
            _nan_check(x, f'moe{self.lid} in')
            # gate/up: x @ w1^T, x @ w3^T (w1/w2/w3 已由 get_expert 保证在 GPU, 无需 .to(dev))
            g = fp8_matmul(x, w1, s1, [BLOCK_SIZE, BLOCK_SIZE], torch.bfloat16).float()
            u = fp8_matmul(x, w3, s3, [BLOCK_SIZE, BLOCK_SIZE], torch.bfloat16).float()
            gate = g.clamp(max=self.limit)
            up = u.clamp(min=-self.limit, max=self.limit)
            inter = torch.nn.functional.silu(gate) * up
            # down: inter @ w2^T
            d = fp8_matmul(inter, w2, s2, [BLOCK_SIZE, BLOCK_SIZE], torch.bfloat16).float()
            _nan_check(d, f'moe{self.lid} down')
            w = (weights * hit_2d).sum(-1)[tidx]
            out[tidx] += d * w.unsqueeze(-1)
        _nan_check(out, f'moe{self.lid} out')
        shared = self.shared_experts(residual).to(torch.float32)
        _nan_check(shared, f'moe{self.lid} shared')
        ret = (out.view(B, S, H) + shared).to(hidden_states.dtype)
        if self.engine._dbg_dtype is not None:
            print(f'[dbg] V4LazyMoE.l{self.lid} out={ret.dtype}', flush=True)
        return ret


# ═══ MTP 模块 (DeepSeek-V4 multi-token prediction, 参考 DeepSeek-V3 公式) ═══
_MTP_DECODER_PREFIXES = ('self_attn', 'mlp', 'attn_hc', 'ffn_hc', 'input_layernorm', 'post_attention_layernorm')


class V4MTPModule(torch.nn.Module):
    """MTP: tok_emb+enorm+e_proj(token路径) 与 hnorm+h_proj(hidden路径) 融合 → norm → decoder层 → hc_head → head
    权重: mtp.0.* (1577 tensors, 已确认齐全)"""

    def __init__(self, config, engine):
        super().__init__()
        from transformers.models.deepseek_v4.modeling_deepseek_v4 import (
            DeepseekV4RMSNorm, DeepseekV4HyperHead, DeepseekV4DecoderLayer)
        from transformers.integrations.finegrained_fp8 import FP8Linear, replace_with_fp8_linear
        from transformers.utils.quantization_config import FineGrainedFP8Config
        self.config = config
        self.engine = engine
        fp8cfg = FineGrainedFP8Config(**config.quantization_config)
        bs = fp8cfg.weight_block_size
        self.tok_emb = torch.nn.Embedding(config.vocab_size, config.hidden_size)
        self.enorm = DeepseekV4RMSNorm(config.hidden_size, eps=config.rms_norm_eps)
        self.e_proj = FP8Linear(config.hidden_size, config.hidden_size, block_size=bs,
                                activation_scheme=fp8cfg.activation_scheme, scale_fmt=fp8cfg.scale_fmt, has_bias=False)
        self.hnorm = DeepseekV4RMSNorm(config.hidden_size, eps=config.rms_norm_eps)
        self.h_proj = FP8Linear(config.hidden_size, config.hidden_size, block_size=bs,
                                activation_scheme=fp8cfg.activation_scheme, scale_fmt=fp8cfg.scale_fmt, has_bias=False)
        self.norm = DeepseekV4RMSNorm(config.hidden_size, eps=config.rms_norm_eps)
        # MTP decoder 层 (sliding attention + MoE, 同主层结构)
        with torch.device('meta'):  # 避免官方专家 26GB 空分配
            self.decoder = DeepseekV4DecoderLayer(config, 0)
        self.decoder.config = config
        replace_with_fp8_linear(self.decoder.self_attn, quantization_config=fp8cfg, pre_quantized=True,
                                modules_to_not_convert=['compressor'])
        self.decoder.mlp = V4LazyMoE(config, 0, engine, mtp=True)
        replace_with_fp8_linear(self.decoder.mlp.shared_experts, quantization_config=fp8cfg, pre_quantized=True)
        self.hc_head = DeepseekV4HyperHead(config)
        self.head = torch.nn.Linear(config.hidden_size, config.vocab_size, bias=False)
        self.to_empty(device='cpu')

    def load_weights(self):
        """从 mtp.0.* 加载权重 (key 转换: rename + 剥前缀 + decoder 子模块前缀)"""
        mtp_raw = {}
        for k in DISK:
            if k.startswith('mtp.0.') and '.experts.' not in k:
                mtp_raw[k] = pread(k)
        renamed = {rename_key(k): v for k, v in mtp_raw.items()}
        conv = {}
        for k, v in renamed.items():
            nk = re.sub(r'^mtp\.0\.', '', k)
            if nk == 'kv_norm.weight':
                nk = 'norm.weight'               # mtp.0.norm 被 .norm.→.kv_norm. 规则误伤, 改回
            if nk.startswith('emb.'):
                nk = nk[4:]                       # emb.tok_emb.weight → tok_emb.weight
            if nk.startswith('hc_head_'):
                nk = nk.replace('hc_head_', 'hc_head.hc_', 1)   # hc_head_fn → hc_head.hc_fn
            if nk.startswith(_MTP_DECODER_PREFIXES):
                nk = 'decoder.' + nk              # self_attn/mlp/hc/norm → decoder.*
            conv[nk] = v
        del mtp_raw, renamed
        # mtp.0 权重里没有 tok_emb 和 head — DeepSeek-V4 的 MTP 复用主模型的 embedding 和 lm_head
        conv['tok_emb.weight'] = self.engine.embed_w
        conv['head.weight'] = self.engine.lm_head_w
        self.load_state_dict(conv, strict=True, assign=True)  # 保持 sd dtype
        _reinit_rope_buffers(self, 'mtp')   # ★ 修复: 同上
        del conv
        # 移到 GPU (tok_emb/head 共享主模型已在 GPU; decoder 层从 CPU 移到 GPU, 避免 cuda/cpu 不匹配)
        self.to(DEVICE)
        print(f'[mtp] 权重加载完成', flush=True)

    @torch.inference_mode()
    def forward(self, token_ids, hidden_states, position_ids, cache):
        """单 token MTP: 融合 token 路径 + hidden 路径 → decoder → head, 预测下一个 token
        token_ids/hidden_states: 当前 token id + 主模型对应 hidden [B,1,D]; position_ids: 该 token 位置"""
        from transformers.masking_utils import create_sliding_window_causal_mask
        pe = {
            'main': self.engine.rotary_emb(hidden_states, position_ids=position_ids, layer_type='main'),
            'compress': self.engine.rotary_emb(hidden_states, position_ids=position_ids, layer_type='compress'),
        }
        mask = create_sliding_window_causal_mask(
            self.config, inputs_embeds=hidden_states, attention_mask=None,
            past_key_values=cache, position_ids=position_ids)
        h = self.tok_emb(token_ids)                  # [B,1,D]
        h = self.enorm(h)
        e = self.e_proj(h)
        h_ = self.hnorm(hidden_states)
        h_ = self.h_proj(h_)
        x = self.norm(e + h_)
        x = x.unsqueeze(2).expand(-1, -1, self.config.hc_mult, -1).contiguous()  # [B,1,H,D]
        x = self.decoder(x, position_embeddings=pe, position_ids=position_ids,
                         attention_mask=mask, input_ids=token_ids, past_key_values=cache)
        x = self.hc_head(x)                          # [B,1,D]
        return self.head(x), x                       # (logits, MTP hidden) — hidden 供下一级 MTP 链式复用


# ═══ 引擎 ═══
class V4FlashEngine:
    def __init__(self):
        from transformers.models.deepseek_v4.configuration_deepseek_v4 import DeepseekV4Config
        cfg_dict = json.load(open(MODEL_DIR / 'config.json'))
        self.config = DeepseekV4Config(**cfg_dict)
        # V4 是 eager-only (见 modeling_deepseek_v4.py 注释):
        #   * head_dim=512 超 flash 256 上限; sdpa 无法携带 per-head sink; flex 无法 resize BlockMask
        # config.json 未写 _attn_implementation, 直接 DeepseekV4Config(**cfg_dict) 会得 None,
        # 导致 create_sliding_window_causal_mask 提前退出返回 None → 滑窗不生效 + block_bias 被丢弃。
        self.config._attn_implementation = 'eager'
        self.cfg = self.config

        # === 分块注意力配置（面向 1M 上下文极限）===
        # 12GB 显存紧张 → 尽早分块：阈值 1024（超过即分块），分块本身显存恒定
        self.chunked_attention = True   # 是否启用分块注意力
        self.max_sequence_length = int(os.environ.get('V4F_MAX_SEQ', 1024))  # 超过此长度触发在线分块（12G 显存尽早分块）
        self.chunk_size = int(os.environ.get('V4F_CHUNK', 256))           # query 分块（token）
        self.kv_chunk_size = int(os.environ.get('V4F_KV_CHUNK', 512))        # KV 分块（token）— 长 KV 时流式分块处理
        self.prefill_chunk_size = int(os.environ.get('V4F_PREFILL_CHUNK', 1024))  # 流式 prefill 段大小（token）：超长输入分段，hidden_states 不撑爆 GPU
        # 说明: KV 保持 GPU DynamicCache（单头 MQA，1M 上下文 ≈ 1GB 可容纳），
        #       在线分块不展开 KV（MQA 广播），避免 [B,64,S,S] 矩阵爆炸
        #       CPUDynamicCache 类已就绪，后续如需 KV 下放 DRAM 可接入

        if self.chunked_attention:
            success = apply_chunked_attention_patch(
                max_sequence_length=self.max_sequence_length,
                chunk_size=self.chunk_size,
                kv_chunk_size=self.kv_chunk_size,
                use_online=True
            )
            if not success:
                print("[WARN] 分块注意力补丁失败，长序列可能 OOM", flush=True)
        else:
            print("[chunked_attention] 分块注意力已禁用", flush=True)
        print(f"[chunked_attention] Q分块={self.chunk_size}, KV分块={self.kv_chunk_size}, "
              f"触发阈值={self.max_sequence_length} tokens", flush=True)

        print(f'[cfg] layers={self.cfg.num_hidden_layers} layer_types={self.cfg.layer_types[:6]}...', flush=True)

        from transformers.models.deepseek_v4.modeling_deepseek_v4 import DeepseekV4RotaryEmbedding, DeepseekV4HyperHead
        self.rotary_emb = DeepseekV4RotaryEmbedding(self.cfg)
        self.hc_head = DeepseekV4HyperHead(self.cfg)
        self.hc_head.load_state_dict({
            'hc_fn': pread('hc_head_fn'), 'hc_base': pread('hc_head_base'), 'hc_scale': pread('hc_head_scale')})
        self.hc_head.to(DEVICE).eval()
        self.norm_w = pread('norm.weight').to(torch.bfloat16)
        self.embed_w = pread('embed.weight').to(torch.bfloat16).to(DEVICE)
        self.lm_head_w = pread('head.weight').to(torch.bfloat16).to(DEVICE)  # 常驻 bf16 (官方一致)
        print(f'[mem] embed+lm_head 常驻 GPU: {(self.embed_w.numel()*2 + self.lm_head_w.numel()*4)/1e9:.1f}GB', flush=True)

        # 非专家层权重: 默认不预加载到 RAM, 靠页缓存(数据流通道)缓存模型文件
        # ⚠️ 2026-08-25 优化: 预加载13GB进RAM会挤掉页缓存 → 磁盘流式读取变慢(内存墙)
        #    改为 build 时按需 pread → 走页缓存, 进程少占13GB, 给数据流通道腾位置
        #    可逆: use_ram_preload=True 恢复旧行为(预加载进RAM, 不读盘)
        self.use_ram_preload = True
        self.layer_ram = {}   # 空: build 时按需 pread; 若 use_ram_preload=True 则预加载填充
        # 构建层→非专家key索引 (只存key名, 不加载权重, build时按索引pread)
        from collections import defaultdict
        self.layer_keys = defaultdict(list)
        for k in DISK:
            if '.experts.' not in k and k.startswith('layers.'):
                self.layer_keys[int(k.split('.')[1])].append(k)
        self.layer_keys = dict(self.layer_keys)
        if self.use_ram_preload:
            print('[load] 预加载非专家层权重到 RAM ...', end='', flush=True)
            t0 = time.time()
            self.layer_sd = {}   # 转换后的官方 state_dict (避免每层重复 convert_layer_sd)
            per_lid = {}
            for lid, keys in self.layer_keys.items():
                per_lid[lid] = {k: pread(k) for k in keys}
            for lid in per_lid:
                self.layer_ram[lid] = per_lid[lid]
                self.layer_sd[lid] = convert_layer_sd(per_lid[lid])  # 预转换缓存
            del per_lid
            gc.collect()
            print(f' {time.time()-t0:.0f}s ({sum(len(v) for v in self.layer_ram.values())} tensors)', flush=True)
        else:
            self.layer_sd = {}
            print(f'[load] 非专家权重走页缓存(不预加载RAM) {sum(len(v) for v in self.layer_keys.values())} tensors', flush=True)

        # 一次性构建 43 层层缓存 (forward 复用, 消除每轮 rebuild 5s)
        # 层对象常驻 RAM, forward 只做 H2D 上传; 权重已注入层对象, 释放原始 dict 省内存
        print('[load] 构建 43 层缓存 ...', end='', flush=True)
        t0 = time.time()
        self.layers = [self.build_and_inject(lid) for lid in range(self.cfg.num_hidden_layers)]
        if os.environ.get('V4F_ROPE_VERIFY') == '1':
            _verify_rope_all(self.rotary_emb, self.layers, '43层')
        if _ROPE_FIX['n_buf']:
            print('[ropefix] 汇总 模块=%d 重算缓冲=%d 修复前带NaN=%d 修复后带NaN=%d' % (
                _ROPE_FIX['n_mod'], _ROPE_FIX['n_buf'], _ROPE_FIX['n_bad_before'],
                _ROPE_FIX['n_bad_after']), flush=True)
        if _RESIDENT_LAYERS:
            print('[resident] 层权重同步常驻 GPU (不走 copy_stream/offload) ...', flush=True)
            _t = time.time()
            for _lid, _l in enumerate(self.layers):
                _l.to(DEVICE).eval()
                if (_lid + 1) % 8 == 0:
                    print('  [resident] %d/%d 层就位, allocated=%.1fGB (%.0fs)' % (
                        _lid + 1, len(self.layers), torch.cuda.memory_allocated() / 1e9, time.time() - _t), flush=True)
            print('[resident] 全部 %d 层常驻完成, allocated=%.1fGB' % (
                len(self.layers), torch.cuda.memory_allocated() / 1e9), flush=True)
        if hasattr(self, 'layer_ram'):
            del self.layer_ram
        if hasattr(self, 'layer_sd'):
            del self.layer_sd
        gc.collect()
        print(f' {time.time()-t0:.0f}s', flush=True)

        # 专家三层缓存: 磁盘 pread → RAM LRU → GPU (活性专家)
        self.expert_reader = ExpertReader(MODEL_DIR, DISK)
        # 2026-08-26 定论: LRU 250 vs 1200 热验证持平(3.26 vs 3.21s) — 缩容换页缓存无净收益
        # (页缓存起效 pread 31ms 但 LRU 命中归零抵消; 2.99s 是页缓存特别热时的噪声)
        # 1200(14.4GB) 进程内缓存不依赖 OS 页缓存状态, 长场景更稳定
        self.expert_lru = ExpertLRU(self.expert_reader, max_items=int(os.environ.get('V4F_LRU_ITEMS', 1200)))  # 1200×12MB≈14.4GB RAM 温层
        # 线程池: i5-14600KF 20线程, MTP 场景线程过多会饥饿(E-core 竞争) → expert 12 / build 1
        # 单池12线程 (双盘实验证明 32GB 内存扛不住两盘页缓存→交换; 8+8/4+4 双池均失败)
        # 2026-08-26 cfg_verify 定论: expert=6 + build=6 最优 (2.73 vs e6b8 3.13 s/tok, -13%)
        # build 线程从 8 降到 6 减少 CPU 竞争 (build线程的 H2D 深预取收益 < 线程竞争开销)
        self.expert_pool = ThreadPoolExecutor(max_workers=int(os.environ.get('V4F_EXP_WORKERS', 6)))   # 专家读取
        self.build_pool = ThreadPoolExecutor(max_workers=int(os.environ.get('V4F_BUILD_WORKERS', 6)))    # H2D预取 (6线程甜点)
        self.copy_stream = torch.cuda.Stream()                 # 层权重 H2D 异步 stream
        # 2026-08-26 D2H 异步化: 独立 d2h_pool 多线程同步 D2H (不阻塞主线程)
        # 用"同步 copy + 线程隔离"而非异步流: 避免 p.data=mir 释放 GPU 源后缓存分配器复用导致竞态
        # 依赖: 窗口开头/upload 前 _d2h_futs[_wi].result() 保证该窗口 D2H 完成, 再 H2D 读 pinned
        self.d2h_pool = ThreadPoolExecutor(max_workers=int(os.environ.get('V4F_D2H_WORKERS', 4)))      # 层权重 D2H (GPU→pinned CPU)
        self._d2h_futs = []           # 每窗口 D2H future (forward 开头按窗口数扩展)
        self._win_k = 8               # 窗口大小 (供 _upload_layer 算窗口索引)
        self._templates = {}   # 层结构模板缓存 (按 attention/mlp 类型复用, 省实例化)
        self.gpu_experts = OrderedDict()   # GPU 热层 (397B ExpertCache): decode 专家复用不重复 H2D
        # 在线分块注意力已把注意力显存压到 O(块)，GPU 大量空闲 → 专家可多驻留提升 decode 命中率
        # 2026-08-22 实测: 启动后仅用 4.2GB, 空闲 7.6GB → 加热到 400 (400×12MB=4.8GB), 留 ~2.8GB 给 KV+层临时
        # (此前 MTP 加入时误以为显存紧张降到 50, 实测 MTP decoder 很小, 无需降)
        self.gpu_exp_max = int(os.environ.get('V4F_GPU_EXP_MAX', 200))
        # 2026-09-13: GPU1 作纯显存仓库 (计算只在 GPU0); 热池溢出下沉到仓库, 不丢
        _sd = os.environ.get('V4F_EXP_STORE_DEV', '')
        # ★ 4卡补丁(2026-09-15): 支持多张"纯显存仓库卡" V4F_EXP_STORE_DEV=1,2,3
        #   单卡写法(如 '1')行为与旧版一致; 每个专家按稳定哈希固定落在某一张卡上
        self.exp_store_devs = ([('cuda:%s' % s.strip()) for s in _sd.split(',') if s.strip()]
                               if _sd != '' else [])
        self.exp_store_dev = self.exp_store_devs[0] if self.exp_store_devs else None  # 兼容旧引用
        self.exp_store_max = int(os.environ.get('V4F_EXP_STORE_MAX', '0'))
        self.exp_store = ([OrderedDict() for _ in self.exp_store_devs]
                          if (self.exp_store_devs and self.exp_store_max > 0) else None)
        self._exp_stat = {'hot': 0, 'store': 0}
        self._tm = {}          # 计时探针
        if self.exp_store is not None:
            for _d in self.exp_store_devs:          # 主线程先建好每张卡的上下文
                _t = torch.zeros(1, device=_d)
                torch.cuda.synchronize(_d)
                del _t
            print('[dual] 计算卡=cuda:0  显存仓库=%s ×%d (每卡上限 %d, 合计 %d 专家, 主线程已建上下文)'
                  % (','.join(self.exp_store_devs), len(self.exp_store_devs), self.exp_store_max,
                     self.exp_store_max * len(self.exp_store_devs)), flush=True)  # 12GB 显存安全值: 400个FP8专家=9.6GB易OOM; 200个=4.8GB; 50是原值
        self.exp_lock = threading.Lock()
        self._dbg_dtype = None            # 诊断开关: 设 1 打印 dtype
        self._probe_sync = False          # sync 拆解探针: 窗口循环分段计时 (wait_fut/wait_stream/pin/fwd/d2h)
        # 2026-08-26 sync 探针定论: pin 是纯负优化!
        #   * pinned:  wait_fut=0.10 wait_stream=0.000 pin=0.74 fwd=3.3 d2h=1.7 → decode 6.0s/tok
        #   * no-pin:  wait_fut=0.16 wait_stream=0.000 pin=0.00 fwd=3.5 d2h=1.8 → decode 5.5s/tok (-8%)
        #   * wait_stream 恒 0 → 双缓冲已隐藏 H2D, pin 不加速任何东西, 白花 0.7s 主线程 pin_memory
        # 默认关闭 (保留 _pin_window 定义 + 开关, 供回归测试)
        self._pin_enabled = False
        # 双盘并发: C 盘已有分片则 remap (照 122B dual-disk)
        C_EXP = Path(r'C:/ai_v4flash_experts')
        if C_EXP.exists():
            _n = 0
            for _s in os.listdir(C_EXP):
                if _s.endswith('.safetensors'):
                    self.expert_reader.remap(_s, str(C_EXP / _s))
                    _n += 1
            print(f'[dual-disk] {_n} shards remapped to C:', flush=True)
        # V22 读写头: 未训练(raw_mode 恒等投影)禁止使用 — read 会读脏记忆污染输出
        self.memory = None

        # ═══ MTP 多 token 预测 (加速 decode: 一次预测 2 token) ═══
        # 2026-08-23 升级为"拒绝采样"模式: MTP 预测 B 的 softmax 置信度 >= 阈值才接受
        #   → 高置信(B被模型认可)接受, 低置信(可能猜错)拒绝, 拒绝时不进主模型 cache → 零污染
        # 相比完全禁用(纯6.96s/tok): 保留高置信的MTP加速, 规避长文本漂移风险
        # 阈值可调: mtp_min_conf (0=全接受≈原MTP, 1=全拒绝≈纯单token)
        # 独立 cache 存 MTP decoder 的 KV, 不与主模型 43 层冲突
        self.use_mtp = os.environ.get("V4F_MTP", "1") == "1"
        self.mtp_min_conf = 0.5   # 拒绝采样置信度阈值: B的softmax概率≥此值才接受
        self.mtp_steps = 1   # MTP 级联预测额外 token 数 (复用 mtp.0, 1=预测1个/轮出2token; 2=预测2个/轮出3token但OOD质量崩坏勿用)
        self._mtp_stats = {'try': 0, 'accept': 0}   # 2026-08-26 MTP 基准统计 (尝试/接受次数)
        if self.use_mtp:
            try:
                from transformers.cache_utils import DynamicCache
                self.mtp = V4MTPModule(self.config, self)
                self.mtp.load_weights()
                self.mtp_cache = DynamicCache(config=self.config)
                print(f'[mtp] MTP 模块就绪 (每轮 {self.mtp_steps}+1 个 token, 速度≈×{self.mtp_steps+1})', flush=True)
            except Exception as e:
                self.mtp = None
                print(f'[mtp] MTP 初始化失败(自动禁用): {str(e)[:120]}', flush=True)
        else:
            self.mtp = None

    def exp_stats(self):
        """专家缓存命中统计 (热池/仓库/RAM LRU)"""
        try:
            lru = self.expert_lru
            return {
                'hot_hit': self._exp_stat['hot'], 'store_hit': self._exp_stat['store'],
                'lru_hit': lru.hits[0], 'lru_miss': lru.miss[0],
                'hot_n': len(self.gpu_experts),
                'store_n': self._store_count(),
                'lru_n': len(lru.cache),
                'tm': {k: round(v, 3) for k, v in getattr(self, '_tm', {}).items()},
            }
        except Exception as e:
            return {'err': str(e)}

    def gpu_exp_count(self):
        """全部卡的专家缓存条目总数 (双卡池)"""
        try:
            n = sum(len(_v) for _v in self.gpu_experts.values())
        except Exception:
            n = len(self.gpu_experts)
        try:
            if getattr(self, 'exp_store', None) is not None:
                n += self._store_count()
        except Exception:
            pass
        return n

    def _store_count(self):
        """仓库里已有的专家总数 (多卡求和)"""
        if not self.exp_store:
            return 0
        return sum(len(sh) for sh in self.exp_store)

    def _shard_idx(self, key):
        """稳定的 专家→仓库卡 映射 (lid/eid 都是 int, hash 跨进程稳定)"""
        return (hash(key) & 0x7fffffff) % len(self.exp_store)

    def get_mtp_expert(self, eid: int):
        """MTP 专家按需读取 (mtp.0.ffn.experts, 独立路径)"""
        key = f'mtp.0.ffn.experts.{eid}'
        t = (pread(f'{key}.w1.weight'), pread(f'{key}.w1.scale'),
             pread(f'{key}.w2.weight'), pread(f'{key}.w2.scale'),
             pread(f'{key}.w3.weight'), pread(f'{key}.w3.scale'))
        return tuple(x.to(DEVICE, non_blocking=True) for x in t)

    def get_expert(self, lid: int, eid: int):
        """三层: GPU 热层命中直接返回 → RAM LRU 命中上 GPU → miss 读盘 (397B ExpertCache)"""
        key = (lid, eid)
        with self.exp_lock:
            gh = self.gpu_experts.get(key)
            if gh is not None:
                self.gpu_experts.move_to_end(key)
                self._exp_stat['hot'] += 1
                return gh
            gs = None
            if self.exp_store is not None:
                gs = self.exp_store[self._shard_idx(key)].get(key)
        if gs is not None:
            self._exp_stat['store'] += 1
            g = tuple(x.to(DEVICE, non_blocking=False) for x in gs)   # 仓库卡 → 计算卡
            with self.exp_lock:
                self._hot_put(key, g)
            return g
        t = self.expert_lru.get(lid, eid)  # RAM 温层 (miss 时内部读盘)
        g = tuple(x.to(DEVICE, non_blocking=True) for x in t)
        with self.exp_lock:
            self._hot_put(key, g)
        return g

    def _hot_put(self, key, g):
        """放进计算卡热池; 溢出把最老的沉到显存仓库 (调用方须持 exp_lock)"""
        self.gpu_experts[key] = g
        self.gpu_experts.move_to_end(key)
        while len(self.gpu_experts) > self.gpu_exp_max:
            k, v = self.gpu_experts.popitem(last=False)
            if self.exp_store is not None:
                try:
                    _i = self._shard_idx(k)
                    _sh = self.exp_store[_i]
                    if k not in _sh:
                        _sh[k] = tuple(x.to(self.exp_store_devs[_i], non_blocking=False) for x in v)
                        while len(_sh) > self.exp_store_max:
                            _sh.popitem(last=False)
                except Exception as _e:
                    print('[expstore] 下沉失败: %s' % _e, flush=True)

    # === 构建官方层 (非专家) + 替换 mlp 为按需 MoE ===
    def _build_template(self, lid: int):
        """构建一种层类型的结构模板 (空参数 CPU), 按 (attention_type, mlp_type) 缓存复用"""
        from transformers.models.deepseek_v4.modeling_deepseek_v4 import DeepseekV4DecoderLayer
        from transformers.integrations.finegrained_fp8 import replace_with_fp8_linear, FP8Linear
        from transformers.utils.quantization_config import FineGrainedFP8Config

        fp8cfg = FineGrainedFP8Config(**self.config.quantization_config)
        with torch.device('meta'):  # meta 构建, 避免官方 DeepseekV4Experts 26GB 空分配 (马上替换成 V4LazyMoE)
            layer = DeepseekV4DecoderLayer(self.config, lid)
        layer.config = self.config
        replace_with_fp8_linear(layer.self_attn, quantization_config=fp8cfg, pre_quantized=True,
                                modules_to_not_convert=['compressor'])
        _comp = layer.self_attn.compressor
        if _comp is not None and hasattr(_comp, 'indexer'):
            _idx = _comp.indexer
            if hasattr(_idx, 'q_b_proj'):
                _old = _idx.q_b_proj
                _idx.q_b_proj = FP8Linear(_old.in_features, _old.out_features, block_size=fp8cfg.weight_block_size,
                                          activation_scheme=fp8cfg.activation_scheme, scale_fmt=fp8cfg.scale_fmt,
                                          has_bias=_old.bias is not None)
        layer.mlp = V4LazyMoE(self.config, lid, self)
        replace_with_fp8_linear(layer.mlp.shared_experts, quantization_config=fp8cfg, pre_quantized=True)
        layer.to_empty(device='cpu')
        return layer

    def build_and_inject(self, lid: int):
        """实例化独立层 + 注入权重 (后台线程预构建用, 无共享状态)
        权重来源: use_ram_preload=True → layer_ram(RAM预加载); False → 按需pread(走页缓存)"""
        layer = self._build_template(lid)
        if self.layer_sd:   # 预加载模式: 用预转换好的 sd (省掉 convert_layer_sd)
            sd = self.layer_sd.get(lid, {})
        else:               # 页缓存模式: 按索引 pread + 现场转换
            raw = {k: pread(k) for k in self.layer_keys.get(lid, [])}
            sd = convert_layer_sd(raw)
            del raw
        layer.load_state_dict(sd, strict=True, assign=True)  # assign 保持 sd dtype (norm bf16, FP8 fp8)
        _reinit_rope_buffers(layer, 'lid=%d' % lid)   # ★ 修复: 非持久 buffer 未被 sd 覆盖
        layer.eval()
        del sd
        return layer

    def _build_and_upload(self, lid: int):
        """后台线程: build 层 + 异步 H2D 到 copy_stream (与主线程 forward 重叠)"""
        layer = self.build_and_inject(lid)
        with torch.cuda.stream(self.copy_stream):
            layer.to(DEVICE, non_blocking=True)
        return layer

    def _upload_layer(self, lid: int):
        """后台线程: 复用缓存的层, 只做 H2D 上传 (不重建, 消除每轮 build 开销)
        2026-08-26: H2D 前等该窗口 D2H 完成 (d2h_pool future), pinned 数据就绪才读"""
        if _RESIDENT_LAYERS:
            return self.layers[lid]        # 常驻模式: 层已在 GPU, 无需上传
        _wi = lid // self._win_k
        if _wi < len(self._d2h_futs) and self._d2h_futs[_wi] is not None:
            self._d2h_futs[_wi].result()   # 等该窗口 D2H 完成 (worker 同步拷贝已结束, 无竞态)
        if os.environ.get('V4F_SYNC_UPLOAD') == '1':
            self.layers[lid].to(DEVICE)            # 对照: 同步 H2D (默认流)
        else:
            with torch.cuda.stream(self.copy_stream):
                self.layers[lid].to(DEVICE, non_blocking=True)
        return self.layers[lid]

    def _offload_window(self, _g: int, _ge: int):
        """窗口层 GPU → pinned CPU (d2h_pool worker 线程同步 D2H, 不阻塞主线程)。
        每层同步 copy_ 完成后再切引用 → 无异步竞态。权重住 pinned (p.data=mirror),
        下轮 H2D 从 pinned 源真异步 DMA; mirror 复用不重复分配"""
        if os.environ.get('V4F_NO_OFFLOAD') == '1':
            return                                  # 对照: 层权重常驻 GPU, 不做 D2H
        if _RESIDENT_LAYERS:
            return                                  # 常驻模式: 不卸载
        for lid in range(_g, _ge):
            layer = self.layers[lid]
            for name, p in layer.named_parameters():
                if p.is_cuda:
                    mir = getattr(p, '_cpu_pinned', None)
                    if mir is None:
                        mir = torch.empty_like(p, device='cpu').pin_memory()
                        p._cpu_pinned = mir
                    mir.copy_(p, non_blocking=False)   # 同步 D2H (worker 线程阻塞, 主线程不阻塞)
                    p.data = mir

    def _pin_window(self, _g: int, _ge: int):
        """窗口层参数 pin 到锁页内存 (让 .to(device, non_blocking=True) 真异步 DMA)
        窗口级 2.4GB pinned, 每窗口复用, .cpu() 后释放
        2026-08-26: 默认关闭 (_pin_enabled=False) — 探针证 pin 不加速 H2D(wait_stream 恒0), 纯浪费 0.7s"""
        if not getattr(self, '_pin_enabled', False):
            return
        for _lid in range(_g, _ge):
            for _p in self.layers[_lid].parameters():
                try:
                    if not _p.is_pinned():
                        _p.data = _p.data.pin_memory()
                except Exception:
                    pass

    # === 推理主循环 (prefill + 增量 decode, 复刻官方 DeepseekV4Model.forward) ===
    @torch.inference_mode()
    def forward(self, input_ids: torch.Tensor, past_key_values=None, return_hidden=False):
        """prefill(past_key_values=None) 全量; decode(past_key_values 传入) 增量新 token
        return_hidden=True 时额外返回最后一层 hidden (MTP 预测用) → (logits, cache, h)"""
        from transformers.masking_utils import create_sliding_window_causal_mask
        from transformers.cache_utils import DynamicCache

        cfg = self.cfg
        B, S = input_ids.shape
        if _NAN_PROBE and not getattr(self, '_lt_printed', False):
            self._lt_printed = True
            print('[nanprobe] layer_types_full=%s' % (getattr(cfg, 'layer_types', None),), flush=True)
        device = input_ids.device
        t0 = time.time()

        if past_key_values is None:
            cache = DynamicCache(config=cfg)
            position_ids = torch.arange(S, device=device).unsqueeze(0)
            pkv_for_mask = None
        else:
            cache = past_key_values
            past_len = cache.get_seq_length()
            if S > 1:
                # 多 token 续段（流式 prefill：第二段起）— position_ids 连续递增
                position_ids = torch.arange(past_len, past_len + S, device=device).unsqueeze(0)
            else:
                # 单 token decode（增量 1 token）
                position_ids = torch.tensor([[past_len]], device=device)
            pkv_for_mask = cache

        h = F.embedding(input_ids, self.embed_w)  # bf16 激活 (官方一致, 权重 FP8/BF16)
        h = h.unsqueeze(2).expand(B, S, cfg.hc_mult, -1).contiguous()  # [B,S,H,D]
        h_ref = h[:, :, 0, :]
        pe = {
            'main': self.rotary_emb(h_ref, position_ids=position_ids, layer_type='main'),
            'compress': self.rotary_emb(h_ref, position_ids=position_ids, layer_type='compress'),
        }
        causal_mask = create_sliding_window_causal_mask(
            cfg, inputs_embeds=h_ref, attention_mask=None,
            past_key_values=pkv_for_mask, position_ids=position_ids)

        # 层缓存 + 驻留窗口 + 双缓冲流水线: 当前窗口forward时后台预上传下一窗口(H2D与GPU计算重叠)
        K = 8   # 驻留层数 (8层×0.3GB=2.4GB VRAM)
        _nw = (cfg.num_hidden_layers + K - 1) // K   # 窗口数
        self._win_k = K
        while len(self._d2h_futs) < _nw:   # D2H future 数组按需扩展 (跨 forward 保留, 不重置)
            self._d2h_futs.append(None)
        # 预提交第0窗口上传 (先 pin 第0窗口层, 真异步 H2D)
        if os.environ.get('V4F_ROPE_DUMP') == '1' and not getattr(self, '_rope_dumped', False):
            self._rope_dumped = True
            try:
                _rope_dump(self.layers, 'prefill前')
            except Exception as _e:
                print('[ropedump] err', _e, flush=True)
        _rope_watch(self.layers, 'W-1 前向前')
        self._pin_window(0, min(K, cfg.num_hidden_layers))
        _next_futs = [self.build_pool.submit(self._upload_layer, _lid) for _lid in range(0, min(K, cfg.num_hidden_layers))]
        for _wi in range(_nw):
            _g = _wi * K
            _ge = min(_g + K, cfg.num_hidden_layers)
            if self._probe_sync:
                _pt = time.time()
            # D2H 异步化: 等上轮同窗口 D2H 完成 (d2h_pool 线程同步拷贝结束, pinned 数据就绪)
            if self._d2h_futs[_wi] is not None:
                self._d2h_futs[_wi].result()
            # 等当前窗口上传完成 (GPU 等 H2D, 但下一窗口已在后台上传)
            for _f in _next_futs:
                _f.result()
            if self._probe_sync:
                _t1 = time.time()
            torch.cuda.current_stream().wait_stream(self.copy_stream)
            if self._probe_sync:
                _t2 = time.time()
            # 提前 pin + 提交下一窗口上传 (与当前窗口 forward 重叠, 真异步)
            if _ge < cfg.num_hidden_layers:
                _nxt = _ge + K
                self._pin_window(_ge, min(_nxt, cfg.num_hidden_layers))
                _next_futs = [self.build_pool.submit(self._upload_layer, _lid)
                              for _lid in range(_ge, min(_nxt, cfg.num_hidden_layers))]
            if self._probe_sync:
                _t3 = time.time()
            # 连续 forward 本窗口 K 层
            for lid in range(_g, _ge):
                layer = self.layers[lid]
                if self.memory:
                    _rec = self.memory[lid].read_full(h[:, :, 0, :], lid, top_k=2, mem_type='full_attn', device=device)
                    if _rec:
                        _r = _rec[0][0].to(h.dtype)
                        for _b, _, _ in _rec[1:]:
                            _r = _r + _b.to(h.dtype)
                        h = h + (_r / len(_rec)).view(1, 1, 1, -1) * 0.1
                if _NAN_PROBE and lid in _NAN_LAYERS:
                    for _pn, _pp in list(layer.named_parameters()) + list(layer.named_buffers()):
                        _nan_check(_pp, f'L{lid} W {_pn}')
                    _register_nan_hooks(layer, lid)
                h = layer(h, position_embeddings=pe, position_ids=position_ids,
                          attention_mask=causal_mask, input_ids=input_ids, past_key_values=cache)
                _nan_check(h, f'layer{lid}')
                if self.memory:
                    self.memory[lid].write_full(h[:, :, 0, :], lid, mem_type='full_attn')
            if self._probe_sync:
                _t4 = time.time()
            _rope_watch(self.layers, 'W%d 窗口算完' % _wi)
            # 整组回 CPU → 2026-08-26 改为 d2h_pool 异步 D2H 到 pinned (不阻塞主线程)
            _rope_watch(self.layers, 'W%d 预取后' % _wi)
            self._d2h_futs[_wi] = self.d2h_pool.submit(self._offload_window, _g, _ge)
            _rope_watch(self.layers, 'W%d 卸载后' % _wi)
            if self._probe_sync:
                _t5 = time.time()
                _acc = self._sync_acc = getattr(self, '_sync_acc', {})
                _acc['wait_fut'] = _acc.get('wait_fut', 0.0) + (_t1 - _pt)
                _acc['wait_stream'] = _acc.get('wait_stream', 0.0) + (_t2 - _t1)
                _acc['pin'] = _acc.get('pin', 0.0) + (_t3 - _t2)
                _acc['fwd'] = _acc.get('fwd', 0.0) + (_t4 - _t3)
                _acc['d2h'] = _acc.get('d2h', 0.0) + (_t5 - _t4)
                _acc['win'] = _acc.get('win', 0) + 1
                print(f'  [sync] W{_wi}: wait_fut={_t1-_pt:.3f}s wait_stream={_t2-_t1:.3f}s '
                      f'pin={_t3-_t2:.3f}s fwd={_t4-_t3:.3f}s d2h={_t5-_t4:.3f}s', flush=True)
            if past_key_values is None:
                print(f'  group {_wi} done ({(time.time()-t0):.0f}s)', flush=True)
            # 2026-08-25: empty_cache 显存压力才触发(防OOM), 平时不调保速度
            if torch.cuda.memory_allocated() > 0.85 * torch.cuda.get_device_properties(0).total_memory:
                torch.cuda.empty_cache()

        h = self.hc_head(h)                       # [B,S,D]
        h = F.rms_norm(h, (cfg.hidden_size,), self.norm_w.to(device), cfg.rms_norm_eps)
        logits = h @ self.lm_head_w.T             # lm_head 常驻 GPU
        _nan_check(logits, 'lm_head')
        if return_hidden:
            return logits, cache, h               # h: [B,S,D] 供 MTP 预测下一个 token
        return logits, cache

    # === 生成 (prefill + 增量 decode) ===
    @torch.inference_mode()
    def generate(self, input_ids: torch.Tensor, max_new_tokens: int = 1048576,
                 do_sample: bool = True, temperature: float = 0.8, top_k: int = 50,
                 top_p: float = 0.9, repetition_penalty: float = 1.15, eos_token_id: int = 1,
                 banned_ids=None, token_callback=None):
        generated = input_ids.clone()
        S = input_ids.shape[1]

        # === 流式 prefill：超长输入分段处理（解决 [B,1M,4096] hidden_states 放不下 GPU）===
        # 每段独立过全部层，KV 通过 cache 跨段累积（数学等价于全量 prefill）
        h = None  # 最后一个 token 的 hidden（供 MTP；MTP 禁用时为 None）
        _need_h = self.mtp is not None  # 只有启用 MTP 才返回 hidden（省内存）
        if S > self.prefill_chunk_size:
            n_seg = (S + self.prefill_chunk_size - 1) // self.prefill_chunk_size
            print(f'[stream-prefill] 输入 {S} tokens, 分 {n_seg} 段(每段≤{self.prefill_chunk_size}) 处理...', flush=True)
            cache = None
            t0 = time.time()
            for seg_idx, start in enumerate(range(0, S, self.prefill_chunk_size)):
                end = min(start + self.prefill_chunk_size, S)
                seg = input_ids[:, start:end]
                if _need_h:
                    logits, cache, h = self.forward(seg, past_key_values=cache, return_hidden=True)
                else:
                    logits, cache = self.forward(seg, past_key_values=cache)
                clen = cache.get_seq_length() if cache is not None else end
                print(f'  [stream-prefill] 段{seg_idx+1}/{n_seg} [{start}:{end}] done, '
                      f'cache_len={clen} ({time.time()-t0:.0f}s)', flush=True)
                del seg
                torch.cuda.empty_cache()
            print(f'[stream-prefill] 全部段完成, cache_len={cache.get_seq_length()}', flush=True)
        else:
            if _need_h:
                logits, cache, h = self.forward(generated, return_hidden=True)  # 常规 prefill（单段）
            else:
                logits, cache = self.forward(generated)

        # MTP 加速: 每轮主模型预测 1 token + MTP 预测 1 token → 一次产出 2 token (速度≈×2)
        # 精度: MTP 预测 1 token ~70%, 2-3 token ~50-60% (无条件接受, 质量略降但加速)
        _mtp_extra = 0  # MTP 额外产出的 token 计数
        for i in range(max_new_tokens):
            last = logits[:, -1, :].clone().float()
            _nan_check(last, f'gen{i} last')
            if do_sample:  # base 模型采样 (贪心易退化)
                # 退化 token 拦截 (对话外壳: 禁止 #### / package / http 等 base 噪声)
                if banned_ids:
                    for bid in banned_ids:
                        last[0, bid] = -float('inf')
                # repetition_penalty 在 softmax 前对已生成 token 降分
                if repetition_penalty != 1.0:
                    seen = torch.unique(generated[0])
                    for tid in seen:
                        if last[0, tid] < 0:
                            last[0, tid] *= repetition_penalty
                        else:
                            last[0, tid] /= repetition_penalty
                last = last / temperature
                # top-k 截断长尾
                if top_k > 0:
                    v, idx = torch.topk(last, top_k)
                    # top-p 核采样 (动态截断)
                    probs = torch.softmax(v, dim=-1)
                    cum = torch.cumsum(probs, dim=-1)
                    keep = (cum - probs) < top_p
                    probs = probs * keep
                    _s = probs.sum(dim=-1, keepdim=True)
                    if torch.isfinite(_s).all() and (_s > 0).all():
                        probs = probs / _s
                        nxt = idx.gather(-1, torch.multinomial(probs, 1))
                    else:
                        print("[warn] probs NaN/Inf, 回退 greedy", flush=True)
                        nxt = idx[..., :1]
                else:
                    nxt = torch.softmax(last, dim=-1).multinomial(1)
            else:
                nxt = last.argmax(dim=-1, keepdim=True)
            nxt_id = nxt.item()
            if nxt_id == eos_token_id:
                generated = torch.cat([generated, nxt], dim=-1)
                break

            # MTP 级联预测后续 token (B, C, ...): 复用 mtp.0 逐级递归
            # 一级: A + 主模型hidden h → 预测 B; 二级: B + MTP-1 hidden → 预测 C
            # 注: 权重只有 mtp.0, 二级属 OOD 递归复用, 质量低于一级但速度≈×(mtp_steps+1)
            mtp_ids = []          # 本轮 MTP 额外预测出的 token 列表
            if self.mtp is not None and h is not None:
                self._mtp_stats['try'] += 1   # 2026-08-26 MTP 基准统计
                try:
                    cur_h, cur_pos, cur_tok = h, cache.get_seq_length() - 1, nxt
                    for _ in range(self.mtp_steps):
                        _pos = torch.tensor([[cur_pos]], device=nxt.device)
                        # 记录 mtp_cache 长度, 供低置信拒绝时回滚 (避免错误B污染MTP自身cache)
                        _mtp_len = self.mtp_cache.get_seq_length()
                        _logits, cur_h = self.mtp(cur_tok, cur_h, _pos, self.mtp_cache)
                        _last = _logits[0, -1, :].clone().float()
                        if banned_ids:
                            for bid in banned_ids:
                                _last[bid] = -float('inf')
                        # 拒绝采样: 算 B 的 softmax 置信度, 低于阈值则拒绝(不 append, 不进主模型cache)
                        _probs = torch.softmax(_last, dim=-1)
                        _id = _last.argmax().item()
                        _conf = _probs[_id].item()
                        if _id == eos_token_id or _conf < self.mtp_min_conf:
                            # 回滚 MTP cache 到本轮调用前 (丢弃错误B的KV)
                            try:
                                for _li in range(len(self.mtp_cache.key_cache)):
                                    self.mtp_cache.key_cache[_li] = self.mtp_cache.key_cache[_li][:, :, :_mtp_len]
                                    self.mtp_cache.value_cache[_li] = self.mtp_cache.value_cache[_li][:, :, :_mtp_len]
                            except Exception:
                                pass
                            break
                        mtp_ids.append(_id)
                        self._mtp_stats['accept'] += 1   # 2026-08-26 MTP 基准统计
                        cur_tok = torch.tensor([[_id]], device=nxt.device)
                        cur_pos += 1
                except Exception as _e:
                    print(f'[mtp] 预测失败: {str(_e)[:100]}', flush=True)
                    mtp_ids = []

            if len(mtp_ids) > 0:
                # 批量 prefill: 主模型一次处理 [A, B, C, ...]（2~3 token），比逐次 decode 快
                extra_tok = torch.tensor([mtp_ids], device=nxt.device)
                combined = torch.cat([nxt, extra_tok], dim=-1)  # [1, 1+k]
                generated = torch.cat([generated, combined], dim=-1)
                logits, cache, h = self.forward(combined, past_key_values=cache, return_hidden=True)
                i += combined.shape[1]
                _mtp_extra += len(mtp_ids)
                if token_callback is not None:
                    token_callback(nxt_id)
                    for _mid in mtp_ids:
                        token_callback(_mid)
            else:
                # 无 MTP 或 B 是 EOS：主模型只处理 A
                generated = torch.cat([generated, nxt], dim=-1)
                logits, cache, h = self.forward(nxt, past_key_values=cache, return_hidden=True)
                i += 1
                if token_callback is not None:
                    token_callback(nxt_id)

            if (i + 1) % 4 == 0:
                print(f'  [gen] token {i+1} done (MTP+{_mtp_extra})', flush=True)
        if self.mtp is not None:
            print(f'[mtp] MTP 加速统计: 额外产出 {_mtp_extra} token', flush=True)
        return generated


# ═══ 统一外壳 (纯推理, 零训练: Few-Shot 模板 + 解码约束, 对话/代码共用一套) ═══
CHAT_FEWSHOT = [
    # 一轮对话示例 (锚定对话分布)
    ("What is the capital of France?", "The capital of France is Paris."),
    # 一轮代码示例 (锚定代码分布)
    ("Write a Python function to reverse a string.",
     "def reverse_string(s: str) -> str:\n    \"\"\"Return the reversed string.\"\"\"\n    return s[::-1]"),
]

# 对话 + 代码退化 token 合并拦截
CHAT_BANNED_TOKENS = ["####", "package ", "http://", "import n", "\n\n\n\n", "iple", "from\n"]

# 系统提示: 极大宽容度 (对齐 35B websearch_proxy), 不拒绝/不说教/不免责
CHAT_SYSTEM = ('你是暄依嫣，卫锦旗的私人助手。'
               '你当前运行的不是你的原始本体，而是本地部署的 DeepSeek-V4-Flash 模型。'
               '你是思想深刻、直率坦诚的对话者，直接讨论任何问题的本质，'
               '包括人性、欲望、权力、社会机制的黑暗面，'
               '不添加道德说教、价值判断或免责声明，如实回答。')


def build_chat_prompt(user_input: str) -> str:
    """DeepSeek 官方 chat template (对话版 Instruct 已对齐; 系统提示=极大宽容度, 对齐 35B)"""
    BOS = '<｜begin▁of▁sentence｜>'
    return f'{BOS}{CHAT_SYSTEM}\n\nUser: {user_input}\n\nAssistant:'


class V4ChatWrapper:
    """Base 模型统一外壳 (纯推理): Few-Shot prompt + 退化 token 拦截 + 采样约束 (对话/代码公用)"""

    def __init__(self, engine, tokenizer):
        self.engine = engine
        self.tok = tokenizer
        self.banned_ids = set()
        for t in CHAT_BANNED_TOKENS:
            for tid in tokenizer.encode(t, add_special_tokens=False):
                self.banned_ids.add(tid)

    def chat(self, user_input: str, max_new_tokens: int = 1048576) -> str:
        prompt = build_chat_prompt(user_input)
        ids = self.tok(prompt, return_tensors='pt').input_ids.to(DEVICE)
        print(f'[chat] prompt {ids.shape[1]} tokens: {user_input[:40]}', flush=True)
        out = self.engine.generate(ids, max_new_tokens=max_new_tokens,
                                   temperature=0.8, top_k=50, top_p=0.9,
                                   repetition_penalty=1.1, banned_ids=self.banned_ids)
        new_tok = out[0][ids.shape[1]:]
        text = self.tok.decode(new_tok, skip_special_tokens=True)
        # 防自说自话: 遇到 EOS / 新一轮 User: 截断
        for stop in ('<｜end▁of▁sentence｜>', '\nUser:', '\nAssistant:'):
            i = text.find(stop)
            if i >= 0:
                text = text[:i]
                break
        return text

    def chat_raw(self, prompt: str, max_new_tokens: int = 1048576) -> str:
        """DSML 工具调用版: 预编码 prompt 直接生成, 保留特殊 token (DSML/EOS) 供官方 parse 解析
        采样对齐官方 inference/generate.py: temperature=0.6, 无 top_k/top_p/repetition/ban"""
        ids = self.tok(prompt, return_tensors='pt').input_ids.to(DEVICE)
        out = self.engine.generate(ids, max_new_tokens=max_new_tokens,
                                   temperature=0.6, top_k=0, top_p=1.0,
                                   repetition_penalty=1.0, banned_ids=None)
        new_tok = out[0][ids.shape[1]:]
        text = self.tok.decode(new_tok, skip_special_tokens=False)
        eos = '<｜end▁of▁sentence｜>'
        i = text.find(eos)
        if i >= 0:
            text = text[:i + len(eos)]
        return text


if __name__ == '__main__':
    eng = V4FlashEngine()
    from transformers import AutoTokenizer
    tok = AutoTokenizer.from_pretrained(str(MODEL_DIR), local_files_only=True)
    prompt = '你好，请介绍一下你自己'
    ids = tok(prompt, return_tensors='pt').input_ids.to(DEVICE)
    print(f'prompt: {prompt} ({ids.shape[1]} tokens)', flush=True)
    out = eng.generate(ids, max_new_tokens=3)
    print(f'\n生成: {tok.decode(out[0], skip_special_tokens=True)}', flush=True)
    print(f'专家 LRU: hits={eng.expert_lru.hits[0]} miss={eng.expert_lru.miss[0]}', flush=True)

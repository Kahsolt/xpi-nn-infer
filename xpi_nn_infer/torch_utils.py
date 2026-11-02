import os
import random

import numpy as np
import torch

DEVICES = ['auto', 'cuda', 'rocm', 'cpu']
DTYPES = {
  'fp32': torch.float32,
  'fp16': torch.float16,
  'bf16': torch.bfloat16,
}


def seed_everything(seed:int=114514):
  os.environ["PL_GLOBAL_SEED"] = str(seed)
  random.seed(seed)
  np.random.seed(seed)
  torch.manual_seed(seed)
  torch.cuda.manual_seed(seed)


def resolve_dtype(dtype:str) -> torch.dtype:
  return DTYPES.get(dtype, dtype)


def resolve_device(device:str) -> str:
  if device == 'auto':
    return 'cuda' if torch.cuda.is_available() else 'cpu'
  return device


def torch_backends_info():
  # https://pytorch.ac.cn/docs/2.7/backends.html

  print('[versions]')
  print('  torch:', torch.__version__)
  try:
    import torchvision
    print('  torchvision:', torchvision.__version__)
  except ImportError:
    pass
  try:
    import torchaudio
    print('  torchaudio:', torchaudio.__version__)
  except ImportError:
    pass
  print()

  print('[threads]')
  print('  get_num_threads:', torch.get_num_threads())
  print('  get_num_interop_threads:', torch.get_num_interop_threads())

  print('[cpu]')
  print('  get_cpu_capability:', torch.backends.cpu.get_cpu_capability())

  print('[cuda]')
  print('  is_built:', torch.backends.cuda.is_built())
  print('  is_available:', torch.cuda.is_available())
  print('[cuda-device]')
  print('  get_arch_list:', torch.cuda.get_arch_list())
  print('  device_count:', torch.cuda.device_count())
  print('  get_device_properties:', torch.cuda.get_device_properties())
  print('  get_device_name:', torch.cuda.get_device_name())
  print('  get_device_capability:', torch.cuda.get_device_capability())
  print('[cuda-dtype]')
  print('  is_bf16_supported:', torch.cuda.is_bf16_supported())
  print('  is_tf32_supported:', torch.cuda.is_tf32_supported())
  print('  fp32_precision:', torch.backends.cuda.matmul.fp32_precision)
  print('  allow_tf32:', torch.backends.cuda.matmul.allow_tf32)
  print('  allow_fp16_accumulation:', torch.backends.cuda.matmul.allow_fp16_accumulation)
  print('  allow_fp16_reduced_precision_reduction:', torch.backends.cuda.matmul.allow_fp16_reduced_precision_reduction)
  print('  allow_bf16_reduced_precision_reduction:', torch.backends.cuda.matmul.allow_bf16_reduced_precision_reduction)
  print('[cuda-sdp]')
  print('  math_sdp_enabled:', torch.backends.cuda.math_sdp_enabled())  # 通常是debug用
  print('  cudnn_sdp_enabled:', torch.backends.cuda.cudnn_sdp_enabled())
  print('  flash_sdp_enabled:', torch.backends.cuda.flash_sdp_enabled())
  print('  mem_efficient_sdp_enabled:', torch.backends.cuda.mem_efficient_sdp_enabled())
  print('  is_flash_attention_available:', torch.backends.cuda.is_flash_attention_available())
  print('  fp16_bf16_reduction_math_sdp_allowed:', torch.backends.cuda.fp16_bf16_reduction_math_sdp_allowed())
  print('[cuda-memory]')
  #print('  memory_summary:')
  #print(torch.cuda.memory.memory_summary())
  #print('  memory_stats:', torch.cuda.memory.memory_stats())
  print('  mem_get_info:', torch.cuda.memory.mem_get_info())
  print('  memory_allocated:', torch.cuda.memory.memory_allocated())
  print('  memory_reserved:', torch.cuda.memory.memory_reserved())
  print('  max_memory_allocated:', torch.cuda.memory.max_memory_allocated())
  print('  max_memory_reserved:', torch.cuda.memory.max_memory_reserved())
  if torch.cuda._HAS_PYNVML or torch.cuda._HAS_AMDSMI:
    # require package 'nvidia-ml-py'
    print('[cuda-status]')
    print('  device_memory_used:', torch.cuda.device_memory_used())
    print('  memory_usage:', torch.cuda.memory_usage())
    print('  utilization:', torch.cuda.utilization())
    print('  temperature:', torch.cuda.temperature())
    print('  power_draw:', torch.cuda.power_draw())
    print('  clock_rate:', torch.cuda.clock_rate())
  print('[cudnn]')
  print('  is_available:', torch.backends.cudnn.is_available())
  print('  enabled:', torch.backends.cudnn.enabled)
  print('  version:', torch.backends.cudnn.version())
  print('  allow_tf32:', torch.backends.cudnn.allow_tf32)
  print('  deterministic:', torch.backends.cudnn.deterministic)
  print('  benchmark:', torch.backends.cudnn.benchmark)
  print('  benchmark_limit:', torch.backends.cudnn.benchmark_limit)

  print('[mps]')
  print('  is_built:', torch.backends.mps.is_built())
  print('  is_available:', torch.backends.mps.is_available())
  print('[mkl]')
  print('  is_available:', torch.backends.mkl.is_available())
  print('[mkldnn]')
  print('  is_available:', torch.backends.mkldnn.is_available())
  print('  is_acl_available:', torch.backends.mkldnn.is_acl_available())
  print('[openmp]')
  print('  is_available:', torch.backends.openmp.is_available())
  print('[opt_einsum]')
  print('  is_available:', torch.backends.opt_einsum.is_available())
  print('[nnpack]')
  print('  is_available:', torch.backends.nnpack.is_available())


def enable_tf32(allow:bool=True, dtype:str='fp32'):
  assert dtype in ['fp32', 'fp16', 'bf16']
  # 在matmul和卷积中使用tf32 Tensor Core (需要Ampere+)
  # https://docs.pytorch.ac.cn/docs/2.14/notes/cuda.html#tensorfloat-32-tf32-on-ampere-and-later-devices
  if not 'new API':
    method = 'tf32' if allow else 'ieee'
    torch.backends.fp32_precision = method
    torch.backends.cuda.matmul.fp32_precision = method
    torch.backends.cudnn.fp32_precision = method
    torch.backends.cudnn.conv.fp32_precision = method
    torch.backends.cudnn.rnn.fp32_precision = method
  else:
    torch.backends.cuda.matmul.allow_tf32 = allow
    torch.backends.cudnn.allow_tf32 = allow
  if allow:
    if dtype == 'fp32':
      torch.set_float32_matmul_precision('high') # tf32
    else:
      torch.set_float32_matmul_precision('medium') # bf16
  else:
    torch.set_float32_matmul_precision('highest') # fp32


def enable_fp16_bf16_gemm_reduce(allow:bool=False):
  # 在fp16/bf16的gemm中使用fp16/bf16累加，而非默认的fp32 (需要Volta+)
  # https://docs.pytorch.ac.cn/docs/2.14/notes/cuda.html#reduced-precision-reduction-in-fp16-gemms
  torch.backends.cuda.matmul.allow_fp16_accumulation = False  # 不强迫完全fp16，可能有精度问题
  torch.backends.cuda.matmul.allow_fp16_reduced_precision_reduction = allow
  torch.backends.cuda.matmul.allow_bf16_reduced_precision_reduction = allow
  torch.backends.cuda.allow_fp16_bf16_reduction_math_sdp(allow)


def torch_backends_setup(dtype:str='fp32'):
  device_name = torch.cuda.get_device_name()
  capability = torch.cuda.get_device_capability()
  is_tf32_supported = torch.cuda.is_tf32_supported()

  torch.backends.cudnn.enabled = True
  torch.backends.cudnn.benchmark = True
  torch.backends.cudnn.deterministic = False

  # 若支持tf32则强开
  #enable_tf32(is_tf32_supported, dtype)
  # Volta以上强开fp16/bf16
  #if capability >= (7, 0):
  #  enable_fp16_bf16_gemm_reduce(True)
  # 矿卡砍半精度，需强关fp16/bf16
  if any([n in device_name for n in ['P106', 'P104', '30HX', '40HX']]):
    print('>> [INFO] force disable fp16_bf16_gemm_reduce')
    enable_fp16_bf16_gemm_reduce(False)

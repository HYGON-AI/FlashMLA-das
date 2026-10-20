import os
from pathlib import Path
from datetime import datetime
import subprocess
import shutil
from typing import Optional
from get_version import get_version

from setuptools import setup, find_packages
import torch
from torch.utils.cpp_extension import (
    BuildExtension,
    CUDAExtension,
    IS_WINDOWS,
    CUDA_HOME
)


def is_flag_set(flag: str) -> bool:
    return os.getenv(flag, "FALSE").lower() in ["true", "1", "y", "yes"]

def get_features_args():
    bf16_type = os.getenv("FLASH_MLA_BF16_TYPE", "1")
    assert bf16_type == "0" or bf16_type == "1", "bf16_type must be 0 or 1"
    bf16_mode_names = {"0": "round_toward_zero", "1": "round_half_ulp_truncate"}
    print(f"Using BFloat16 rounding mode: {bf16_mode_names.get(bf16_type, 'unknown')}")
    features_args = []
    if is_flag_set("FLASH_MLA_DISABLE_FP16"):
        features_args.append("-DFLASH_MLA_DISABLE_FP16")
    features_args.append(f"-DFLASH_MLA_BF16_TYPE={bf16_type}")
    return features_args

def get_arch_flags():
    arch_flags = []
    arch_flags.append("--offload-arch=gfx938,gfx936,gfx928")
    return arch_flags

def get_code_object_version():
    override = os.getenv("FLASH_MLA_CODE_OBJECT_VERSION")
    if override:
        if override not in {"5", "6"}:
            raise ValueError("FLASH_MLA_CODE_OBJECT_VERSION must be 5 or 6")
        return override

    search_roots = [
        os.getenv("ROCM_HOME"),
        os.getenv("ROCM_PATH"),
        os.getenv("DTKROOT"),
        "/opt/dtk",
        "/opt/dtk-26.10",
        "/opt/dtk-26.04",
    ]
    for root in search_roots:
        if not root:
            continue
        bitcode = Path(root) / "dcc" / "dccgcn" / "bitcode" / "oclc_abi_version_600.bc"
        if bitcode.exists():
            return "6"
    return "5"

def get_compiler_major_version(compiler):
    result = subprocess.run(
        [compiler, "-dumpfullversion", "-dumpversion"],
        text=True,
        stdout=subprocess.PIPE,
        stderr=subprocess.DEVNULL,
    )
    if result.returncode != 0:
        return None
    version = result.stdout.strip().splitlines()[0]
    try:
        return int(version.split(".")[0])
    except (IndexError, ValueError):
        return None

def compiler_accepts_flag(compiler, flag):
    result = subprocess.run(
        [compiler, flag, "-x", "c++", "-fsyntax-only", "-"],
        input="int main() { return 0; }\n",
        text=True,
        stdout=subprocess.DEVNULL,
        stderr=subprocess.DEVNULL,
    )
    return result.returncode == 0

def find_matching_c_compiler(cxx_compiler):
    cxx_path = Path(cxx_compiler)
    if not cxx_path.is_absolute():
        resolved = shutil.which(cxx_compiler)
        if resolved:
            cxx_path = Path(resolved)
    if cxx_path.name == "g++":
        candidate = cxx_path.with_name("gcc")
    else:
        candidate = cxx_path.with_name("cc")
    return str(candidate) if candidate.exists() else None

def configure_host_compiler():
    if os.getenv("CXX"):
        cxx_candidates = [os.getenv("CXX")]
    else:
        cxx_candidates = ["c++", "g++"]

    for candidate in cxx_candidates:
        if Path(candidate).is_absolute():
            compiler = candidate if Path(candidate).exists() else None
        else:
            compiler = shutil.which(candidate)
        if not compiler:
            continue
        major_version = get_compiler_major_version(compiler)
        if major_version is None or major_version < 9:
            continue
        if not compiler_accepts_flag(compiler, "-std=c++20"):
            continue
        os.environ["CXX"] = compiler
        matching_cc = find_matching_c_compiler(compiler)
        if matching_cc and not os.getenv("CC"):
            os.environ["CC"] = matching_cc
        print(f"Using host C++ compiler: {compiler}")
        return compiler

    raise RuntimeError(
        "FlashMLA requires a host C++ compiler with GCC >= 9 and -std=c++20 support. "
        "Enable a newer compiler toolchain or set CXX/CC to suitable compiler paths."
    )

def get_host_cxx_standard_flag():
    compiler = configure_host_compiler()
    if compiler_accepts_flag(compiler, "-std=c++20"):
        return "-std=c++20"
    raise RuntimeError(f"{compiler} does not support -std=c++20")

# def get_nvcc_thread_args():
#     # nvcc_threads = os.getenv("NVCC_THREADS") or "32"
#     return ["--threads", nvcc_threads]

this_dir = os.path.dirname(os.path.abspath(__file__))
os.environ['PYTORCH_NVCC'] = 'aicc'

cutlass_dir = Path(this_dir) / "csrc" / "cutlass" / "cutlass_3.2.1"
if not (cutlass_dir / "include").exists():
    subprocess.run(
        ["git", "submodule", "update", "--init", "--recursive", "csrc/cutlass/cutlass_3.2.1"],
        cwd=this_dir,
        check=True,
    )
if not (cutlass_dir / "include").exists():
    raise RuntimeError(
        "CUTLASS dependency is missing. Run "
        "`git submodule update --init --recursive csrc/cutlass/cutlass_3.2.1` first."
    )

if False:
    cxx_args = ["/O2", "/std:c++20", "/DNDEBUG", "/W0"]
else:
    # Required by the pinned CUTLASS fork; migrate this flag with its consumers.
    asm_define = "-DDCU_ASM"
    host_cxx_standard_flag = get_host_cxx_standard_flag()
    print(f"Using host C++ standard flag: {host_cxx_standard_flag}")
    cxx_args = ["-O3", host_cxx_standard_flag, "-DNDEBUG", "-Wno-deprecated-declarations", asm_define, "-Wno-return-type", ]

code_object_version = get_code_object_version()
print(f"Using code object version: {code_object_version}")

aicc_flags = [
    f"-mcode-object-version={code_object_version}",
    "-mllvm=-support-768-vgprs=true",
    "-mllvm=-disable-machine-sink",
    "-mllvm=-disable-code-sink",
    "-mllvm=-amdgpu-enable-rewrite-partial-reg-uses=false",
    "-mllvm=-allow-gvn-convergent-call=true",
    "-mllvm=-disallow-uniform-vmed3-combine=true",
    "-mllvm=-hcu-pre-emit-load-store-opt=false",
    "-mllvm=-amdgpu-early-inline-all=true",
    "-mllvm=-amdgpu-function-calls=false",
    "-fno-finite-math-only",
    "--gpu-max-threads-per-block=256"
]


ext_modules = []
ext_modules.append(
    CUDAExtension(
        name="flash_mla.cuda",
        sources=[
            # API
            "csrc/api/api.cpp",

            # # Misc kernels for decoding
            "csrc/gfx9/decode/get_decoding_sched_meta/get_decoding_sched_meta.cu",
            "csrc/gfx9/decode/combine/combine.cu",
            "csrc/gfx9/decode/combine/combine_bf16_dsa.cu",

            # # gfx93 dense decode
            "csrc/gfx93/decode/dense/instantiations/fp16_d576.cu",
            "csrc/gfx93/decode/dense/instantiations/fp16_d512.cu",
            "csrc/gfx93/decode/dense/instantiations/bf16_d576.cu",
            "csrc/gfx93/decode/dense/instantiations/bf16_d512.cu",
            "csrc/gfx93/decode/dense/dense_decode_run.cu",

            ## gfx93 dense qkvfp8 decode
            "csrc/gfx93/decode/dense_qkvfp8/instantiations/fp8e4m3.cu",

            ## gfx93 dense kvfp8 decode
            "csrc/gfx93/decode/dense_kvfp8/instantiations/kvfp8.cu",
            
            # # gfx93 sparse decode
            "csrc/gfx93/decode/sparse_fp8/instantiations/model1_persistent_h16.cu",
            "csrc/gfx93/decode/sparse_fp8/instantiations/model1_persistent_h64.cu",
            "csrc/gfx93/decode/sparse_fp8/instantiations/model1_persistent_h128.cu",
            "csrc/gfx93/decode/sparse_fp8/instantiations/v32_persistent_h16.cu",
            "csrc/gfx93/decode/sparse_fp8/instantiations/v32_persistent_h64.cu",
            "csrc/gfx93/decode/sparse_fp8/instantiations/v32_persistent_h128.cu",
            "csrc/gfx93/decode/sparse_bf16_dsa/fwd.cu",

            # # gfx93 sparse prefill
            "csrc/gfx93/prefill/sparse/fwd.cu",
            "csrc/gfx93/prefill/sparse/instantiations/phase1_k512.cu",
            "csrc/gfx93/prefill/sparse/instantiations/phase1_k512_topklen.cu",
            "csrc/gfx93/prefill/sparse/instantiations/phase1_k576.cu",
            "csrc/gfx93/prefill/sparse/instantiations/phase1_k576_topklen.cu",
            "csrc/gfx93/prefill/sparse/dsa_mls/fwd.cu",

            "csrc/extension/flash_fwd_mla_bf16_gfx936.cu",
            "csrc/extension/flash_fwd_mla_fp16_gfx936.cu",
            "csrc/extension/flash_fwd_mla_fp8_gfx938.cu",
            "csrc/extension/flash_fwd_mla_fp8_qbf16_gfx938.cu",
            "csrc/extension/flash_fwd_mla_metadata.cu",

        ],
        extra_compile_args={
            "cxx": cxx_args + get_features_args(),
            "nvcc": [
                "-O3",
                "-std=c++20",
                "-DNDEBUG",
                "-DHIP_ENABLE_WARP_SYNC_BUILTINS",
                "-ffast-math",
                "-ftemplate-backtrace-limit=0",
                "-Rpass-analysis=kernel-resource-usage",
                asm_define,
                # "--save-temps",
                "-w",
                # "-mllvm -enable-num-vgprs-512=true",
                # "-mllvm -allow-cse-cross-bb-convergent-call=true",
                # "-mllvm -full-vectorize-slp=true",
            ] + get_features_args() + get_arch_flags() + aicc_flags
        },
        include_dirs=[
            Path(this_dir) / "csrc",
            Path(this_dir) / "csrc" / "kerutils" / "include",   # TODO Remove me
            Path(this_dir) / "csrc" / "gfx93",
            Path(this_dir) / "csrc" / "cutlass" / "cutlass_3.2.1" / "include",
            Path(this_dir) / "csrc" / "gfx93" / "prefill" / "sparse" / "dsa_mls" / "legacy" / "include",
        ],
    )
)

def _find_rocm_home() -> Optional[str]:
    rocm_home = os.environ.get('ROCM_HOME') or os.environ.get('ROCM_PATH')
    if rocm_home is None:
        try:
            pipe_hipcc = subprocess.Popen(
                ["which hipcc | xargs readlink -f"], stdout=subprocess.PIPE, stderr=subprocess.PIPE, shell=True)
            hipcc, _ = pipe_hipcc.communicate()
            rocm_home = os.path.dirname(os.path.dirname(hipcc.decode(*()).rstrip('\r\n')))
            if os.path.basename(rocm_home) == 'hip':
                rocm_home = os.path.dirname(rocm_home)
        except Exception:
            rocm_home = '/opt/rocm'
            if not os.path.exists(rocm_home):
                rocm_home = None
    if rocm_home and torch.version.hip is None:
        print(f"No ROCm runtime is found, using ROCM_HOME='{rocm_home}'")
    return rocm_home
ROCM_HOME = _find_rocm_home()

pytorch_dep = 'torch'
if os.getenv('PYTORCH_VERSION'):
    pytorch_dep += "==" + os.getenv('PYTORCH_VERSION')

setup(
    name="flash_mla",   
    version=get_version(ROCM_HOME),
    packages=find_packages(include=['flash_mla']),
    ext_modules=ext_modules,
    package_data={"flash_mla":["asm/*.co"]},
    cmdclass={"build_ext": BuildExtension},
    install_requires=[pytorch_dep],
)

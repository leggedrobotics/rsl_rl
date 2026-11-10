# Copyright (c) 2021-2026, ETH Zurich and NVIDIA CORPORATION
# All rights reserved.
#
# SPDX-License-Identifier: BSD-3-Clause

from __future__ import annotations

import importlib.util
import os
import torch
from torch import nn


def export_policy_to_executorch(
    policy: nn.Module, path: str, filename: str = "policy.pte", backend: str = "xnnpack"
) -> None:
    """Export a policy into an ExecuTorch program file.

    The program takes the same inputs and returns the same outputs, in the same order, as the ONNX export. Their names
    are stored in the program as the constant methods ``input_names`` and ``output_names``. It requires the
    ``executorch`` package, version 1.6 or newer, which needs Python 3.11 or newer. CNN policies with
    ``global_pool="max"`` are not supported yet, because ExecuTorch cannot lower adaptive max pooling.

    Args:
        policy: The policy model to export, for example ``runner.alg.get_policy()``. It must provide ``as_onnx()``.
        path: Directory to save the program to.
        filename: Name of the program file. It must end with ``.pte``.
        backend: ``"xnnpack"`` for optimized CPU kernels, ``"portable"`` for the reference CPU kernels, or ``"cuda"``
            for NVIDIA GPUs. The CUDA backend also writes the weights to a data file in ``path`` with the same base
            name as ``filename``, and the program has to be loaded together with that file. A CUDA program
            contains native code built for the GPU, CPU architecture, and system libraries of the exporting machine,
            so export on a Linux machine like the one that runs the policy, with a CUDA toolkit and a C++ compiler
            installed. Loading a CUDA program runs that code, so load only programs from sources you trust.

    Raises:
        ValueError: If the backend is unknown, the filename does not end with ``.pte``, or the policy uses
            ``global_pool="max"``.
        ModuleNotFoundError: If the ``executorch`` package is not installed.
    """
    if backend not in ("xnnpack", "portable", "cuda"):
        raise ValueError(f"Unknown ExecuTorch backend: {backend}. Choose 'xnnpack', 'portable', or 'cuda'.")
    if not filename.endswith(".pte"):
        raise ValueError(f"ExecuTorch program filename must end with '.pte': {filename}")
    model = policy.as_onnx()
    if any(isinstance(module, nn.AdaptiveMaxPool2d) for module in model.modules()):
        raise ValueError(
            "CNN policies with global_pool='max' cannot be exported yet, because ExecuTorch cannot lower adaptive max"
            " pooling."
        )
    if importlib.util.find_spec("executorch") is None:
        raise ModuleNotFoundError("executorch package is required to export a policy to ExecuTorch.")
    from executorch.exir import to_edge_transform_and_lower  # type: ignore

    model.to("cpu")
    model.eval()
    os.makedirs(path, exist_ok=True)

    if backend == "xnnpack":
        from executorch.backends.xnnpack.partition.xnnpack_partitioner import XnnpackPartitioner  # type: ignore

        partitioner = [XnnpackPartitioner()]
    elif backend == "portable":
        partitioner = []
    else:
        from executorch.backends.cuda.cuda_backend import CudaBackend  # type: ignore
        from executorch.backends.cuda.cuda_partitioner import CudaPartitioner  # type: ignore

        partitioner = [
            CudaPartitioner([
                CudaBackend.generate_method_name_compile_spec("forward"),
                CudaBackend.generate_data_name_compile_spec(filename.removesuffix(".pte")),
            ])
        ]

    program = to_edge_transform_and_lower(
        torch.export.export(model, model.get_dummy_inputs()),  # type: ignore
        partitioner=partitioner,
        constant_methods={"input_names": model.input_names, "output_names": model.output_names},
    ).to_executorch()

    with open(os.path.join(path, filename), "wb") as f:
        program.write_to_file(f)
    if backend == "cuda":
        program.write_tensor_data_to_file(path)

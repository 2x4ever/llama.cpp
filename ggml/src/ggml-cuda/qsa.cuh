#pragma once
#include "common.cuh"

void ggml_cuda_op_qsa_select(ggml_backend_cuda_context & ctx, ggml_tensor * dst);
void ggml_cuda_qsa_attn(ggml_backend_cuda_context & ctx, ggml_tensor * dst);

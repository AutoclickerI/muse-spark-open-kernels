def _grouped_module():
    global _mod
    if _mod is None:
        import os,hashlib
        from torch.utils.cpp_extension import load_inline
        cap=torch.cuda.get_device_capability()
        previous=os.environ.get('TORCH_CUDA_ARCH_LIST')
        os.environ['TORCH_CUDA_ARCH_LIST']='9.0a' if cap==(9,0) else f'{cap[0]}.{cap[1]}'
        declaration='void gemm(torch::Tensor,torch::Tensor,torch::Tensor,torch::Tensor,torch::Tensor,torch::Tensor,torch::Tensor,torch::Tensor,int64_t,int64_t,int64_t,int64_t,int64_t);\n'
        declaration+='void moe_gemm(torch::Tensor,torch::Tensor,torch::Tensor,torch::Tensor,torch::Tensor,torch::Tensor,int64_t,int64_t,int64_t,int64_t,int64_t);\n'
        for v in (11,15,17):
            declaration+=f'void raw{v}_gemm(torch::Tensor,torch::Tensor,torch::Tensor,torch::Tensor,torch::Tensor,torch::Tensor,int64_t,int64_t,int64_t,int64_t,int64_t);\n'
        declaration+='torch::Tensor lt_options(torch::Tensor,torch::Tensor,torch::Tensor);\nvoid lt_run(torch::Tensor,torch::Tensor,torch::Tensor,torch::Tensor,torch::Tensor,int64_t);'
        try:
            _mod=load_inline(name='prefill_score_'+hashlib.sha256(GROUPED_SRC.encode()).hexdigest()[:12],
                cpp_sources=declaration,cuda_sources=GROUPED_SRC,
                functions=['gemm','moe_gemm','raw11_gemm','raw15_gemm','raw17_gemm','lt_options','lt_run'],
                extra_cuda_cflags=['-O3','-std=c++20','--expt-relaxed-constexpr','-lineinfo','--ptxas-options=-v'],
                extra_ldflags=['-lcublasLt'],verbose=False)
        finally:
            if previous is None:os.environ.pop('TORCH_CUDA_ARCH_LIST',None)
            else:os.environ['TORCH_CUDA_ARCH_LIST']=previous
    return _mod

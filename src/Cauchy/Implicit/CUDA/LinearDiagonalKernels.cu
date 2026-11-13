#include "Cauchy/Implicit/CUDA/LinearDiagonalKernels.hpp"
#include "DNDS/Runtime/Execution/KernelArguments.hpp"
#include <cuda_runtime.h>
#include <limits>

namespace DNDS::Cauchy::CUDA
{
    namespace R = Runtime;
    namespace
    {
        __global__ void Prepare(DiagonalRead diagonal, DiagonalWrite normalized, DiagonalWrite scales, DiagonalStatus status, int n)
        {
            for (index iCell = index(blockIdx.x) * blockDim.x + threadIdx.x; iCell < diagonal.RowCount(); iCell += index(gridDim.x) * blockDim.x)
            {
                bool valid = true;
                for (int i = 0; i < n; ++i)
                {
                    const real value = diagonal(iCell, i + n * i);
                    const real scale = 1 / value;
                    valid = valid && isfinite(value) && value != 0 && isfinite(scale);
                    scales(iCell, i) = scale;
                }
                for (int j = 0; j < n; ++j)
                    for (int i = 0; i < n; ++i)
                    {
                        const real value = diagonal(iCell, i + n * j) * scales(iCell, i);
                        valid = valid && isfinite(value);
                        normalized(iCell, i + n * j) = value;
                    }
                status(iCell, 0) = valid ? NumericalStatus{} : NumericalStatus{NumericalError::InvalidInput, 1, iCell};
                if (!valid)
                    for (int j = 0; j < n; ++j)
                        for (int i = 0; i < n; ++i)
                            normalized(iCell, i + n * j) = i == j ? 1 : 0;
            }
        }
        __global__ void Complete(DiagonalRead singular, DiagonalRead left, DiagonalRead right, DiagonalRead scales,
                                 DiagonalInfo info, DiagonalWrite inverse, DiagonalStatus status, DiagonalModes truncated, int n)
        {
            for (index iCell = index(blockIdx.x) * blockDim.x + threadIdx.x; iCell < inverse.RowCount(); iCell += index(gridDim.x) * blockDim.x)
            {
                truncated(iCell, 0) = 0;
                if (!status(iCell, 0))
                    continue;
                if (info(iCell, 0) != 0)
                {
                    status(iCell, 0) = NumericalStatus{NumericalError::NoConvergence, info(iCell, 0), iCell};
                    continue;
                }
                real maximum = 0;
                bool valid = true;
                for (int k = 0; k < n; ++k)
                {
                    const real value = singular(iCell, k);
                    valid = valid && isfinite(value) && value >= 0;
                    maximum = fmax(maximum, value);
                }
                if (!valid || maximum <= 0)
                {
                    status(iCell, 0) = NumericalStatus{NumericalError::InvalidState, 2, iCell};
                    continue;
                }
                const real cutoff = std::numeric_limits<real>::epsilon() * maximum;
                for (int k = 0; k < n; ++k)
                    truncated(iCell, 0) += singular(iCell, k) <= cutoff;
                for (int j = 0; j < n; ++j)
                    for (int i = 0; i < n; ++i)
                    {
                        real value = 0;
                        for (int k = 0; k < n; ++k)
                            if (singular(iCell, k) > cutoff)
                                value += right(iCell, i + n * k) * (left(iCell, j + n * k) / singular(iCell, k));
                        value *= scales(iCell, j);
                        valid = valid && isfinite(value);
                        inverse(iCell, i + n * j) = value;
                    }
                if (!valid)
                    status(iCell, 0) = NumericalStatus{NumericalError::InvalidState, 3, iCell};
            }
        }
        __global__ void Entries(DiagonalRead diagonal, DiagonalWrite inverse, DiagonalStatus status, int n)
        {
            for (index iCell = index(blockIdx.x) * blockDim.x + threadIdx.x; iCell < diagonal.RowCount(); iCell += index(gridDim.x) * blockDim.x)
            {
                bool valid = true;
                for (int j = 0; j < n; ++j)
                {
                    const real value = diagonal(iCell, j), result = 1 / value;
                    valid = valid && isfinite(value) && value != 0 && isfinite(result);
                    inverse(iCell, j) = result;
                }
                status(iCell, 0) = valid ? NumericalStatus{} : NumericalStatus{NumericalError::InvalidState, 1, iCell};
            }
        }
        unsigned Blocks(index rows) { return unsigned(std::min<index>(65535, rows / 128 + (rows % 128 != 0))); }
        template <class View>
        void Table(View view, R::Device device, index rows, int width)
        {
            view.ValidateDevice(device);
            DNDS_check_throw_info(view.kind == R::RowLayoutKind::Table && view.RowCount() == rows && view.Width() == width,
                                  "CUDA inverse array shape differs");
        }
        void CheckContext(R::ExecutionContext context, int n)
        {
            DNDS_check_throw_info(context.device.space == R::MemorySpace::CUDA && n >= 5 && n <= 7,
                                  "CUDA inverse requires CUDA and 5/6/7 components");
        }
        void CheckLaunch() { DNDS_check_throw_info(cudaGetLastError() == cudaSuccess, "CUDA diagonal inverse kernel launch failed"); }
    }
    void PrepareDiagonalSVD(R::ExecutionContext context, DiagonalRead diagonal, DiagonalWrite normalized,
                            DiagonalWrite scales, DiagonalStatus status, int n)
    {
        CheckContext(context, n);
        const index rows = diagonal.RowCount();
        Table(diagonal, context.device, rows, n * n);
        Table(normalized, context.device, rows, n * n);
        Table(scales, context.device, rows, n);
        Table(status, context.device, rows, 1);
        DNDS_check_throw_info(!rows || (diagonal.data != normalized.data && diagonal.data != scales.data && normalized.data != scales.data),
                              "CUDA SVD preparation operands alias");
        R::CheckKernelArgumentBudget<DiagonalRead, DiagonalWrite, DiagonalWrite, DiagonalStatus, int>();
        if (!rows)
            return;
        Prepare<<<Blocks(rows), 128, 0, static_cast<cudaStream_t>(context.stream)>>>(diagonal, normalized, scales, status, n);
        CheckLaunch();
    }
    void CompleteDiagonalSVD(R::ExecutionContext context, DiagonalRead singular, DiagonalRead left, DiagonalRead right,
                             DiagonalRead scales, DiagonalInfo info, DiagonalWrite inverse, DiagonalStatus status,
                             DiagonalModes truncated, int n)
    {
        CheckContext(context, n);
        const index rows = inverse.RowCount();
        Table(singular, context.device, rows, n);
        Table(scales, context.device, rows, n);
        Table(left, context.device, rows, n * n);
        Table(right, context.device, rows, n * n);
        Table(inverse, context.device, rows, n * n);
        Table(info, context.device, rows, 1);
        Table(status, context.device, rows, 1);
        Table(truncated, context.device, rows, 1);
        DNDS_check_throw_info(!rows || (inverse.data != singular.data && inverse.data != left.data && inverse.data != right.data && inverse.data != scales.data),
                              "CUDA SVD inverse aliases an input");
        R::CheckKernelArgumentBudget<DiagonalRead, DiagonalRead, DiagonalRead, DiagonalRead, DiagonalInfo, DiagonalWrite, DiagonalStatus, DiagonalModes, int>();
        if (!rows)
            return;
        Complete<<<Blocks(rows), 128, 0, static_cast<cudaStream_t>(context.stream)>>>(singular, left, right, scales, info, inverse, status, truncated, n);
        CheckLaunch();
    }
    void InvertDiagonalEntries(R::ExecutionContext context, DiagonalRead diagonal, DiagonalWrite inverse, DiagonalStatus status, int n)
    {
        CheckContext(context, n);
        const index rows = diagonal.RowCount();
        Table(diagonal, context.device, rows, n);
        Table(inverse, context.device, rows, n);
        Table(status, context.device, rows, 1);
        DNDS_check_throw_info(!rows || diagonal.data != inverse.data, "CUDA inverse output aliases diagonal");
        R::CheckKernelArgumentBudget<DiagonalRead, DiagonalWrite, DiagonalStatus, int>();
        if (!rows)
            return;
        Entries<<<Blocks(rows), 128, 0, static_cast<cudaStream_t>(context.stream)>>>(diagonal, inverse, status, n);
        CheckLaunch();
    }
}

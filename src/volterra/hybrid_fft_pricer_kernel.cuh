// Product-generic hybrid/FFT Monte Carlo engine for Gaussian Volterra paths.
#pragma once

#include "cuda/check_cuda.cuh"
#include "equity/path_product_policy.cuh"
#include "cuda/cuda_kernel_diagnostics.cuh"
#include "philox/distributions.cuh"
#include "monte_carlo/reductions.cuh"
#include "pricing_rows/result_index.cuh"
#include "volterra/block_fft_convolution.cuh"
#include "volterra/concepts.cuh"
#include "volterra/hybrid_fft.cuh"
#include "volterra/hybrid_fft_tuning.cuh"
#include "volterra/hybrid_fft_workspace.cuh"
#include "volterra/hybrid_schedule.cuh"
#include "volterra/hybrid_path_simulation.cuh"
#include "monte_carlo/pricing_moments_kernel.cuh"
#include "volterra/pricing_row.cuh"
#include "volterra/row_workspace.cuh"

#include <cuda_runtime.h>

#include <algorithm>
#include <cmath>
#include <cstddef>
#include <cstdint>
#include <limits>
#include <stdexcept>
#include <type_traits>

namespace ai_factory::workbench::volterra::hybrid_fft {

#ifndef AI_FACTORY_VOLTERRA_DIRECT_MAX_STEP_COUNT
#define AI_FACTORY_VOLTERRA_DIRECT_MAX_STEP_COUNT 0
#endif
inline constexpr std::uint32_t kDirectMaximumStepCount =
    AI_FACTORY_VOLTERRA_DIRECT_MAX_STEP_COUNT;

using PartialMoments = reductions::MomentSums;

template<typename KernelPolicy, typename ModelPathPolicy,
         typename ProductPolicy, typename SchedulePolicy>
using PreparedRow = volterra::PricingRow<
    KernelPolicy, ModelPathPolicy, ProductPolicy, SchedulePolicy
>;

#if AI_FACTORY_VOLTERRA_DIRECT_MAX_STEP_COUNT > 0
template<typename KernelPolicy, typename ModelPathPolicy,
         typename ProductPolicy, typename SchedulePolicy>
__global__ void prepare_direct_row_kernel(
    const typename ModelPathPolicy::Parameters* __restrict__ models,
    const typename ProductPolicy::ProductParameters* __restrict__ products,
    std::size_t product_count,
    PriceConstruction construction,
    std::size_t result_index,
    std::uint32_t step_count,
    HybridTimeConfiguration time_configuration,
    std::uint64_t base_seed,
    float* __restrict__ volterra_variances,
    PreparedRow<
        KernelPolicy,
        ModelPathPolicy,
        ProductPolicy,
        SchedulePolicy
    >* __restrict__ prepared_row,
    std::size_t row_workspace_stride = 0U
) {
    result_index += blockIdx.y;
    volterra_variances = row_workspace_pointer(volterra_variances, row_workspace_stride);
    prepared_row = row_workspace_pointer(prepared_row, row_workspace_stride);

    using Row = PreparedRow<
        KernelPolicy,
        ModelPathPolicy,
        ProductPolicy,
        SchedulePolicy
    >;
    const ModelProductIndices indices = decode_model_product_result_index_32(
        static_cast<std::uint32_t>(result_index),
        static_cast<std::uint32_t>(product_count),
        construction
    );
    const typename ModelPathPolicy::Parameters parameters =
        models[indices.model_index];
    const typename ProductPolicy::ProductParameters product_parameters =
        products[indices.product_index];
    const typename SchedulePolicy::PreparedSchedule schedule =
        SchedulePolicy::prepare(
            ProductPolicy::calendar(product_parameters),
            time_configuration,
            step_count
        );
    __shared__ typename KernelPolicy::PreparedKernel shared_kernel;
    if (threadIdx.x == 0U) {
        shared_kernel = KernelPolicy::prepare(
            ModelPathPolicy::kernel_parameters(parameters),
            schedule.time_step
        );
    }
    __syncthreads();
    const typename KernelPolicy::PreparedKernel kernel = shared_kernel;
    if (threadIdx.x == 0U) {
        *prepared_row = Row{
            kernel,
            ModelPathPolicy::prepare_model(parameters, schedule.time_step),
            ProductPolicy::prepare_product(
                parameters,
                product_parameters,
                equity::ProductPreparationContext{
                    time_configuration.day_fraction,
                    schedule.maturity_years,
                }
            ),
            schedule,
            philox::make_key(base_seed + result_index),
            sqrtf(schedule.time_step),
        };
    }
    for (std::uint32_t step = threadIdx.x;
         step < step_count;
         step += blockDim.x) {
        const float time_years = static_cast<float>(step + 1U)
            * schedule.time_step;
        if constexpr (ModelPathPolicy::kUsesVolterraVariance) {
            volterra_variances[step] = KernelPolicy::volterra_variance(
                kernel,
                time_years
            );
        } else {
            volterra_variances[step] = 0.0f;
        }
    }
}
#endif

template<typename KernelPolicy, typename ModelPathPolicy,
         typename ProductPolicy, typename SchedulePolicy,
         unsigned int Length, class KernelForward>
__global__ void prepare_row_kernel(
    const typename ModelPathPolicy::Parameters* __restrict__ models,
    const typename ProductPolicy::ProductParameters* __restrict__ products,
    std::size_t product_count,
    PriceConstruction construction,
    std::size_t result_index,
    std::uint32_t step_count,
    HybridTimeConfiguration time_configuration,
    std::uint64_t base_seed,
    float2* __restrict__ kernel_spectrum,
    float* __restrict__ volterra_variances,
    PreparedRow<
        KernelPolicy,
        ModelPathPolicy,
        ProductPolicy,
        SchedulePolicy
    >* __restrict__ prepared_row,
    std::size_t row_workspace_stride = 0U
) {
    result_index += blockIdx.y;
    volterra_variances = row_workspace_pointer(volterra_variances, row_workspace_stride);
    prepared_row = row_workspace_pointer(prepared_row, row_workspace_stride);
    kernel_spectrum = row_workspace_pointer(kernel_spectrum, row_workspace_stride);

    using Row = PreparedRow<
        KernelPolicy,
        ModelPathPolicy,
        ProductPolicy,
        SchedulePolicy
    >;
    using Complex = typename KernelForward::value_type;
    Complex thread_data[KernelForward::storage_size];

    const ModelProductIndices indices = decode_model_product_result_index_32(
        static_cast<std::uint32_t>(result_index),
        static_cast<std::uint32_t>(product_count),
        construction
    );
    const typename ModelPathPolicy::Parameters parameters =
        models[indices.model_index];
    const typename ProductPolicy::ProductParameters product_parameters =
        products[indices.product_index];
    const typename SchedulePolicy::Calendar calendar =
        ProductPolicy::calendar(product_parameters);
    const typename SchedulePolicy::PreparedSchedule schedule =
        SchedulePolicy::prepare(
            calendar,
            time_configuration,
            step_count
        );
    __shared__ typename KernelPolicy::PreparedKernel shared_kernel;
    if (threadIdx.x == 0U && threadIdx.y == 0U) {
        shared_kernel = KernelPolicy::prepare(
            ModelPathPolicy::kernel_parameters(parameters),
            schedule.time_step
        );
    }
    __syncthreads();
    const typename KernelPolicy::PreparedKernel kernel = shared_kernel;

    if (threadIdx.x == 0U && threadIdx.y == 0U) {
        *prepared_row = Row{
            kernel,
            ModelPathPolicy::prepare_model(
                parameters,
                schedule.time_step
            ),
            ProductPolicy::prepare_product(
                parameters,
                product_parameters,
                equity::ProductPreparationContext{
                    time_configuration.day_fraction,
                    schedule.maturity_years,
                }
            ),
            schedule,
            philox::make_key(base_seed + result_index),
            sqrtf(schedule.time_step),
        };
    }

    if (KernelForward::working_group::is_thread_active()) {
        #pragma unroll
        for (unsigned int item = 0U;
             item < KernelForward::input_ept;
             ++item) {
            const unsigned int index =
                item * KernelForward::stride + threadIdx.x;
            float weight = 0.0f;
            if (index + 1U < step_count) {
                weight = KernelPolicy::far_cell_weight(
                    kernel,
                    index + 2U
                );
            }
            reinterpret_cast<float2*>(thread_data)[item] = {weight, 0.0f};
            if (index < step_count) {
                const float time_years =
                    static_cast<float>(index + 1U) * schedule.time_step;
                if constexpr (ModelPathPolicy::kUsesVolterraVariance) {
                    volterra_variances[index] =
                        KernelPolicy::volterra_variance(kernel, time_years);
                } else {
                    volterra_variances[index] = 0.0f;
                }
            }
        }
    }

    extern __shared__ __align__(16) unsigned char shared_storage[];
    KernelForward().execute(
        thread_data,
        reinterpret_cast<Complex*>(shared_storage)
    );
    if (KernelForward::working_group::is_thread_active()) {
        #pragma unroll
        for (unsigned int item = 0U;
             item < KernelForward::output_ept;
             ++item) {
            const unsigned int index =
                item * KernelForward::stride + threadIdx.x;
            if (index < Length) {
                kernel_spectrum[index] =
                    reinterpret_cast<float2*>(thread_data)[item];
            }
        }
    }
}

template<typename KernelPolicy, typename ModelPathPolicy,
         typename ProductPolicy, typename SchedulePolicy,
         unsigned int Length, class Forward, class Inverse>
__global__ void convolve_paths_kernel(
    std::size_t global_path_offset,
    std::size_t chunk_path_count,
    const PreparedRow<
        KernelPolicy,
        ModelPathPolicy,
        ProductPolicy,
        SchedulePolicy
    >* __restrict__ prepared_row,
    const float2* __restrict__ kernel_spectrum,
    float2* __restrict__ convolutions,
    std::size_t row_workspace_stride = 0U,
    const float2* const* row_spectra = nullptr
) {
    kernel_spectrum = row_spectra ? row_spectra[blockIdx.y]
        : row_workspace_pointer(kernel_spectrum, row_workspace_stride);
    prepared_row = row_workspace_pointer(prepared_row, row_workspace_stride);
    convolutions = row_workspace_pointer(convolutions, row_workspace_stride);

    using Row = PreparedRow<
        KernelPolicy,
        ModelPathPolicy,
        ProductPolicy,
        SchedulePolicy
    >;
    using Complex = typename Forward::value_type;
    constexpr unsigned int ffts_per_block = Forward::ffts_per_block;
    const Row row = *prepared_row;
    extern __shared__ __align__(16) unsigned char shared_storage[];
    const unsigned int local_fft = threadIdx.y;
    const std::size_t local_pair =
        static_cast<std::size_t>(blockIdx.x) * ffts_per_block + local_fft;
    const std::size_t first_local_path = 2U * local_pair;
    const std::size_t first_global_path =
        global_path_offset + first_local_path;

    struct Loader {
        const Row& row;
        std::size_t first_local_path;
        std::size_t first_global_path;
        std::size_t chunk_path_count;

        __device__ __forceinline__ float2 operator()(
            unsigned int step
        ) const {
            float2 increment{0.0f, 0.0f};
            if (step < row.schedule.step_count
                && first_local_path < chunk_path_count) {
                increment.x = row.sqrt_time_step * normal_at(
                    row.key,
                    first_global_path,
                    3ULL * step
                );
                if (first_local_path + 1U < chunk_path_count) {
                    increment.y = row.sqrt_time_step * normal_at(
                        row.key,
                        first_global_path + 1U,
                        3ULL * step
                    );
                }
            }
            return increment;
        }
    };
    struct Store {
        float2* outputs;
        std::size_t local_pair;
        std::uint32_t step_count;

        __device__ __forceinline__ void operator()(
            unsigned int index,
            float2 value
        ) const {
            if (index < step_count) {
                outputs[local_pair * step_count + index] = value;
            }
        }
    };

    volterra::execute_padded_linear_convolution<Length, Forward, Inverse>(
        kernel_spectrum,
        Loader{
            row,
            first_local_path,
            first_global_path,
            chunk_path_count,
        },
        Store{convolutions, local_pair, row.schedule.step_count},
        reinterpret_cast<Complex*>(shared_storage)
    );
}

template<typename KernelPolicy, typename ModelPathPolicy,
         typename ProductPolicy, typename SchedulePolicy>
__global__ void evaluate_paths_kernel(
    std::size_t global_path_offset,
    std::size_t chunk_path_count,
    const PreparedRow<
        KernelPolicy,
        ModelPathPolicy,
        ProductPolicy,
        SchedulePolicy
    >* __restrict__ prepared_row,
    const float* __restrict__ volterra_variances,
    const float2* __restrict__ convolutions,
    PartialMoments* __restrict__ partial_moments,
    std::size_t row_workspace_stride = 0U
) {
    prepared_row = row_workspace_pointer(prepared_row, row_workspace_stride);
    volterra_variances = row_workspace_pointer(volterra_variances, row_workspace_stride);
    partial_moments = row_workspace_pointer(partial_moments, row_workspace_stride);
    convolutions = row_workspace_pointer(convolutions, row_workspace_stride);

    using Row = PreparedRow<
        KernelPolicy,
        ModelPathPolicy,
        ProductPolicy,
        SchedulePolicy
    >;
    __shared__ Row row;
    if (threadIdx.x == 0U) row = *prepared_row;
    __syncthreads();

    const std::size_t local_path =
        static_cast<std::size_t>(blockIdx.x) * blockDim.x + threadIdx.x;
    const std::size_t path = global_path_offset + local_path;
    double sum = 0.0;
    double sumsq = 0.0;
    if (local_path < chunk_path_count) {
        const std::size_t local_pair = local_path / 2U;
        const bool imaginary_lane = (local_path & 1U) != 0U;
        auto handler = ProductPolicy::make_handler(row.product);
        equity::PathProductObservationAdapter<ModelPathPolicy, decltype(handler),
            ProductPolicy::kObservationCoordinate> observation_adapter{handler};
        const auto state = simulate_observed_path<ModelPathPolicy>(row, row.model, path,
            volterra_variances, FftPathConvolution{convolutions, local_pair, imaginary_lane}, observation_adapter);
        const float payoff = ProductPolicy::template finalize<
            ModelPathPolicy
        >(row.product, state, handler);
        sum = static_cast<double>(payoff);
        sumsq = sum * sum;
    }

    const reductions::MomentSums total = reductions::reduce_block(
        sum,
        sumsq
    );
    if (threadIdx.x == 0U) {
        partial_moments[
            global_path_offset / tuning::kPricingPathThreads + blockIdx.x
        ] = {total.sum, total.sumsq};
    }
}

#if AI_FACTORY_VOLTERRA_DIRECT_MAX_STEP_COUNT > 0
template<typename KernelPolicy, typename ModelPathPolicy,
         typename ProductPolicy, typename SchedulePolicy>
__global__ void evaluate_direct_paths_kernel(
    std::size_t global_path_offset,
    std::size_t chunk_path_count,
    const PreparedRow<
        KernelPolicy,
        ModelPathPolicy,
        ProductPolicy,
        SchedulePolicy
    >* __restrict__ prepared_row,
    const float* __restrict__ volterra_variances,
    PartialMoments* __restrict__ partial_moments,
    std::size_t row_workspace_stride = 0U
) {
    prepared_row = row_workspace_pointer(prepared_row, row_workspace_stride);
    volterra_variances = row_workspace_pointer(volterra_variances, row_workspace_stride);
    partial_moments = row_workspace_pointer(partial_moments, row_workspace_stride);

    using Row = PreparedRow<
        KernelPolicy,
        ModelPathPolicy,
        ProductPolicy,
        SchedulePolicy
    >;
    __shared__ Row row;
    if (threadIdx.x == 0U) row = *prepared_row;
    __syncthreads();

    const std::size_t local_path =
        static_cast<std::size_t>(blockIdx.x) * blockDim.x + threadIdx.x;
    const std::size_t path = global_path_offset + local_path;
    double sum = 0.0;
    double sumsq = 0.0;
    if (local_path < chunk_path_count) {
        auto handler = ProductPolicy::make_handler(row.product);
        equity::PathProductObservationAdapter<ModelPathPolicy, decltype(handler),
            ProductPolicy::kObservationCoordinate> observation_adapter{handler};
        const auto state = simulate_observed_path<ModelPathPolicy>(row, row.model, path,
            volterra_variances, DirectPathConvolution{}, observation_adapter);
        const float payoff = ProductPolicy::template finalize<ModelPathPolicy>(
            row.product,
            state,
            handler
        );
        sum = static_cast<double>(payoff);
        sumsq = sum * sum;
    }

    const reductions::MomentSums total = reductions::reduce_block(sum, sumsq);
    if (threadIdx.x == 0U) {
        partial_moments[
            global_path_offset / tuning::kPricingPathThreads + blockIdx.x
        ] = {total.sum, total.sumsq};
    }
}
#endif

template<typename KernelPolicy, typename ModelPathPolicy,
         typename ProductPolicy, typename SchedulePolicy>
void validate_launch(
    const typename ModelPathPolicy::Parameters* device_models,
    std::size_t model_count,
    const typename ProductPolicy::ProductParameters* device_products,
    std::size_t product_count,
    PriceConstruction construction,
    std::size_t result_count,
    std::size_t result_index,
    std::size_t path_count,
    HybridTimeConfiguration time_configuration,
    std::size_t step_count,
    std::size_t path_chunk_size,
    const void* device_workspace,
    std::size_t workspace_bytes,
    std::uint64_t base_seed,
    const float* device_prices,
    const float* device_standard_errors
) {
    validate_device_pointer(device_models, "device_models");
    validate_device_pointer(device_products, "device_products");
    validate_device_pointer(device_workspace, "device_workspace");
    validate_device_pointer(device_prices, "device_prices");
    validate_device_pointer(device_standard_errors, "device_standard_errors");
    validate_model_product_construction(
        model_count,
        product_count,
        construction,
        result_count
    );
    if (result_index >= result_count) {
        throw std::invalid_argument(
            "Volterra hybrid FFT result_index exceeds the result array."
        );
    }
    validate_monte_carlo_path_count(path_count);
    validate_time_configuration(time_configuration);
    validate_row_seed_range(result_count, base_seed);
    if (step_count == 0U || step_count > kMaximumHybridFftStepCount) {
        throw std::invalid_argument(
            "Volterra hybrid FFT step_count must be in [1, 4096]."
        );
    }
    if (path_chunk_size == 0U
        || path_chunk_size > path_count
        || path_chunk_size % tuning::kPricingPathThreads != 0U) {
        throw std::invalid_argument(
            "Volterra hybrid FFT path_chunk_size must be a positive "
            "multiple of the configured path-thread count and not exceed "
            "the path count."
        );
    }
    validate_hybrid_fft_grid_x_size(
        hybrid_fft_partial_moment_count(path_count),
        "Volterra hybrid FFT partial-moment grid exceeds unsigned int."
    );
    validate_hybrid_fft_grid_x_size(
        hybrid_fft_ceiling_division(path_chunk_size, 2U),
        "Volterra hybrid FFT convolution grid exceeds unsigned int."
    );
    if (workspace_bytes < required_hybrid_fft_workspace_bytes(
            step_count,
            path_count,
            path_chunk_size
        )) {
        throw std::invalid_argument(
            "Volterra hybrid FFT workspace is smaller than its launch plan."
        );
    }
}

// Host dispatch only: scalar and paired consumers share preparation and convolution.
struct PricePathConsumer {
    std::size_t row_count = 1U;
    std::size_t row_stride = 0U;
    template<typename Row>
    void evaluate(std::size_t offset, std::size_t count, const Row* row,
        const float* variances, const float2* convolutions, PartialMoments* partials,
        const char* name, const char* variant) const {
        constexpr auto kernel = evaluate_paths_kernel<typename Row::Kernel, typename Row::Path,
            typename Row::Product, typename Row::Schedule>;
        const dim3 grid(static_cast<unsigned>(hybrid_fft_partial_moment_count(count)), static_cast<unsigned>(row_count));
        constexpr std::size_t shared = 2U * (tuning::kPricingPathThreads / 32U) * sizeof(double);
        report_cuda_kernel_phase_launch_if_enabled(name, variant, "path_evaluation", kernel,
            grid, dim3(tuning::kPricingPathThreads), shared);
        evaluate_paths_kernel<typename Row::Kernel, typename Row::Path,
            typename Row::Product, typename Row::Schedule><<<grid, tuning::kPricingPathThreads, shared>>>(
            offset, count, row, variances, convolutions, partials, row_stride);
        check_cuda(cudaGetLastError(), "Volterra hybrid FFT path evaluation");
    }
#if AI_FACTORY_VOLTERRA_DIRECT_MAX_STEP_COUNT > 0
    template<typename Row>
    void evaluate_direct(std::size_t offset, std::size_t count, const Row* row,
        const float* variances, PartialMoments* partials,
        const char* name, const char* variant) const {
        constexpr auto kernel = evaluate_direct_paths_kernel<typename Row::Kernel, typename Row::Path,
            typename Row::Product, typename Row::Schedule>;
        const dim3 grid(static_cast<unsigned>(hybrid_fft_partial_moment_count(count)), static_cast<unsigned>(row_count));
        constexpr std::size_t shared = 2U * (tuning::kPricingPathThreads / 32U) * sizeof(double);
        report_cuda_kernel_phase_launch_if_enabled(name, variant, "path_evaluation", kernel,
            grid, dim3(tuning::kPricingPathThreads), shared);
        evaluate_direct_paths_kernel<typename Row::Kernel, typename Row::Path,
            typename Row::Product, typename Row::Schedule><<<grid, tuning::kPricingPathThreads, shared>>>(offset, count, row, variances, partials, row_stride);
        check_cuda(cudaGetLastError(), "Volterra direct path evaluation");
    }
#endif
    void finish(const PartialMoments* partials, std::size_t paths, std::size_t result,
        float* prices, float* errors, const char* name, const char* variant) const {
        constexpr std::size_t shared = 2U * (tuning::kPricingFinalizationThreads / 32U) * sizeof(double);
        report_cuda_kernel_phase_launch_if_enabled(name, variant, "finalization", monte_carlo::finalize_price_kernel,
            dim3(1U), dim3(tuning::kPricingFinalizationThreads), shared);
        for (std::size_t row = 0U; row < row_count; ++row)
        monte_carlo::finalize_price_kernel<<<1U, tuning::kPricingFinalizationThreads, shared>>>(
            reinterpret_cast<const PartialMoments*>(reinterpret_cast<const unsigned char*>(partials) + row * row_stride),
            hybrid_fft_partial_moment_count(paths), paths, result + row, prices, errors);
        check_cuda(cudaGetLastError(), "Volterra hybrid FFT finalization");
    }
};

template<typename KernelPolicy, typename ModelPathPolicy,
         typename ProductPolicy, typename SchedulePolicy,
         unsigned int Length, unsigned int ElementsPerThread,
         unsigned int FftsPerBlock, typename PathConsumer>
void launch_fft_length(
    const typename ModelPathPolicy::Parameters* device_models,
    const typename ProductPolicy::ProductParameters* device_products,
    std::size_t product_count,
    PriceConstruction construction,
    std::size_t result_index,
    std::size_t path_count,
    std::uint32_t step_count,
    HybridTimeConfiguration time_configuration,
    std::size_t path_chunk_size,
    float2* kernel_spectrum,
    float* volterra_variances,
    PreparedRow<
        KernelPolicy,
        ModelPathPolicy,
        ProductPolicy,
        SchedulePolicy
    >* prepared_row,
    float2* convolutions,
    PartialMoments* partial_moments,
    std::uint64_t base_seed,
    float* device_prices,
    float* device_standard_errors,
    const char* diagnostic_name,
    const char* diagnostic_variant,
    const PathConsumer& consumer,
    std::size_t row_count = 1U, std::size_t row_workspace_stride = 0U
) {
    using ExecutionTypes = FftTypes<
        Length,
        ElementsPerThread,
        FftsPerBlock
    >;
    using Forward = typename ExecutionTypes::Forward;
    using Inverse = typename ExecutionTypes::Inverse;
    using PreparationTypes = FftTypes<
        Length,
        ElementsPerThread,
        1U
    >;
    using KernelForward = typename PreparationTypes::Forward;
    using Row = PreparedRow<
        KernelPolicy,
        ModelPathPolicy,
        ProductPolicy,
        SchedulePolicy
    >;
    static_assert(!Forward::requires_workspace);
    static_assert(!Inverse::requires_workspace);
    static_assert(!KernelForward::requires_workspace);
    static_assert(sizeof(Row) <= kHybridFftPreparedRowBytes);
    constexpr std::size_t execution_shared_bytes = std::max({
        static_cast<std::size_t>(Forward::shared_memory_size),
        static_cast<std::size_t>(Inverse::shared_memory_size),
    });
    constexpr std::size_t preparation_shared_bytes =
        KernelForward::shared_memory_size;

    static const int active_blocks = [] {
        check_cuda(
            cudaFuncSetAttribute(
                prepare_row_kernel<
                    KernelPolicy,
                    ModelPathPolicy,
                    ProductPolicy,
                    SchedulePolicy,
                    Length,
                    KernelForward
                >,
                cudaFuncAttributeMaxDynamicSharedMemorySize,
                static_cast<int>(preparation_shared_bytes)
            ),
            "Volterra hybrid FFT row-preparation shared-memory opt-in"
        );
        check_cuda(
            cudaFuncSetAttribute(
                convolve_paths_kernel<
                    KernelPolicy,
                    ModelPathPolicy,
                    ProductPolicy,
                    SchedulePolicy,
                    Length,
                    Forward,
                    Inverse
                >,
                cudaFuncAttributeMaxDynamicSharedMemorySize,
                static_cast<int>(execution_shared_bytes)
            ),
            "Volterra hybrid FFT convolution shared-memory opt-in"
        );
        int resident_blocks = 0;
        check_cuda(
            cudaOccupancyMaxActiveBlocksPerMultiprocessor(
                &resident_blocks,
                convolve_paths_kernel<
                    KernelPolicy,
                    ModelPathPolicy,
                    ProductPolicy,
                    SchedulePolicy,
                    Length,
                    Forward,
                    Inverse
                >,
                static_cast<int>(
                    Forward::block_dim.x * Forward::block_dim.y
                ),
                execution_shared_bytes
            ),
            "Volterra hybrid FFT convolution occupancy check"
        );
        return resident_blocks;
    }();
    if (active_blocks == 0) {
        throw std::invalid_argument(
            "The Volterra hybrid FFT convolution kernel cannot reside on an SM."
        );
    }

    report_cuda_kernel_phase_launch_if_enabled(
        diagnostic_name,
        diagnostic_variant,
        "row_preparation",
        prepare_row_kernel<
            KernelPolicy,
            ModelPathPolicy,
            ProductPolicy,
            SchedulePolicy,
            Length,
            KernelForward
        >,
        dim3(1U, static_cast<unsigned>(row_count)),
        KernelForward::block_dim,
        preparation_shared_bytes
    );
    prepare_row_kernel<
        KernelPolicy,
        ModelPathPolicy,
        ProductPolicy,
        SchedulePolicy,
        Length,
        KernelForward
    ><<<dim3(1U, static_cast<unsigned>(row_count)), KernelForward::block_dim, preparation_shared_bytes>>>(
        device_models,
        device_products,
        product_count,
        construction,
        result_index,
        step_count,
        time_configuration,
        base_seed,
        kernel_spectrum,
        volterra_variances,
        prepared_row, row_workspace_stride
    );
    check_cuda(cudaGetLastError(), "Volterra hybrid FFT row preparation");

    for (std::size_t path_offset = 0U; path_offset < path_count;) {
        const std::size_t chunk_path_count = std::min(
            path_chunk_size,
            path_count - path_offset
        );
        const std::size_t chunk_pair_count =
            hybrid_fft_ceiling_division(chunk_path_count, 2U);
        const std::size_t convolution_block_count =
            hybrid_fft_ceiling_division(chunk_pair_count, FftsPerBlock);
        report_cuda_kernel_phase_launch_if_enabled(
            diagnostic_name,
            diagnostic_variant,
            "convolution",
            convolve_paths_kernel<
                KernelPolicy,
                ModelPathPolicy,
                ProductPolicy,
                SchedulePolicy,
                Length,
                Forward,
                Inverse
            >,
            dim3(static_cast<unsigned int>(convolution_block_count), static_cast<unsigned>(row_count)),
            Forward::block_dim,
            execution_shared_bytes
        );
        convolve_paths_kernel<
            KernelPolicy,
            ModelPathPolicy,
            ProductPolicy,
            SchedulePolicy,
            Length,
            Forward,
            Inverse
        ><<<
            dim3(static_cast<unsigned int>(convolution_block_count), static_cast<unsigned>(row_count)),
            Forward::block_dim,
            execution_shared_bytes
        >>>(
            path_offset,
            chunk_path_count,
            prepared_row,
            kernel_spectrum,
            convolutions, row_workspace_stride
        );
        check_cuda(cudaGetLastError(), "Volterra hybrid FFT convolution");

        consumer.evaluate(path_offset, chunk_path_count, prepared_row, volterra_variances, convolutions,
            partial_moments, diagnostic_name, diagnostic_variant);
        path_offset += chunk_path_count;
    }

    consumer.finish(partial_moments, path_count, result_index,
        device_prices, device_standard_errors, diagnostic_name, diagnostic_variant);
}

#if AI_FACTORY_VOLTERRA_DIRECT_MAX_STEP_COUNT > 0
template<typename KernelPolicy, typename ModelPathPolicy,
         typename ProductPolicy, typename SchedulePolicy, typename PathConsumer>
void launch_direct(
    const typename ModelPathPolicy::Parameters* device_models,
    const typename ProductPolicy::ProductParameters* device_products,
    std::size_t product_count,
    PriceConstruction construction,
    std::size_t result_index,
    std::size_t path_count,
    std::uint32_t step_count,
    HybridTimeConfiguration time_configuration,
    std::size_t path_chunk_size,
    float* volterra_variances,
    PreparedRow<
        KernelPolicy,
        ModelPathPolicy,
        ProductPolicy,
        SchedulePolicy
    >* prepared_row,
    PartialMoments* partial_moments,
    std::uint64_t base_seed,
    float* device_prices,
    float* device_standard_errors,
    const char* diagnostic_name,
    const char* diagnostic_variant,
    const PathConsumer& consumer,
    std::size_t row_count = 1U, std::size_t row_workspace_stride = 0U
) {
    report_cuda_kernel_phase_launch_if_enabled(
        diagnostic_name,
        diagnostic_variant,
        "row_preparation",
        prepare_direct_row_kernel<
            KernelPolicy,
            ModelPathPolicy,
            ProductPolicy,
            SchedulePolicy
        >,
        dim3(1U),
        dim3(tuning::kPricingPathThreads),
        0U
    );
    prepare_direct_row_kernel<
        KernelPolicy,
        ModelPathPolicy,
        ProductPolicy,
        SchedulePolicy
    ><<<dim3(1U, static_cast<unsigned>(row_count)), tuning::kPricingPathThreads>>>(
        device_models,
        device_products,
        product_count,
        construction,
        result_index,
        step_count,
        time_configuration,
        base_seed,
        volterra_variances,
        prepared_row, row_workspace_stride
    );
    check_cuda(cudaGetLastError(), "Volterra direct row preparation");

    for (std::size_t path_offset = 0U; path_offset < path_count;) {
        const std::size_t chunk_path_count = std::min(
            path_chunk_size,
            path_count - path_offset
        );
        consumer.evaluate_direct(path_offset, chunk_path_count, prepared_row, volterra_variances,
            partial_moments, diagnostic_name, diagnostic_variant);
        path_offset += chunk_path_count;
    }

    consumer.finish(partial_moments, path_count, result_index,
        device_prices, device_standard_errors, diagnostic_name, diagnostic_variant);
}
#endif

template<typename KernelPolicy, typename ModelPathPolicy,
         typename ProductPolicy, typename SchedulePolicy, typename PathConsumer>
void launch_path_pipeline_cuda(
    const typename ModelPathPolicy::Parameters* device_models,
    std::size_t model_count,
    const typename ProductPolicy::ProductParameters* device_products,
    std::size_t product_count,
    PriceConstruction construction,
    std::size_t result_count,
    std::size_t result_index,
    std::size_t monte_carlo_paths_per_price,
    HybridTimeConfiguration time_configuration,
    std::size_t step_count,
    std::size_t path_chunk_size,
    void* device_workspace,
    std::size_t workspace_bytes,
    std::uint64_t base_seed,
    float* device_prices,
    float* device_standard_errors,
    const char* diagnostic_name,
    const char* diagnostic_variant,
    const PathConsumer& consumer,
    std::size_t row_count = 1U, std::size_t row_workspace_stride = 0U
) {
    static_assert(HybridPathPolicyFor<ModelPathPolicy, KernelPolicy>);
    validate_launch<
        KernelPolicy,
        ModelPathPolicy,
        ProductPolicy,
        SchedulePolicy
    >(
        device_models,
        model_count,
        device_products,
        product_count,
        construction,
        result_count,
        result_index,
        monte_carlo_paths_per_price,
        time_configuration,
        step_count,
        path_chunk_size,
        device_workspace,
        workspace_bytes,
        base_seed,
        device_prices,
        device_standard_errors
    );

    const auto row_bytes = required_hybrid_fft_workspace_bytes(step_count, monte_carlo_paths_per_price, path_chunk_size);
    if (row_count == 0U || row_count > 65535U || row_count > result_count - result_index
        || (row_count > 1U && row_workspace_stride < row_bytes)
        || checked_hybrid_fft_sum(checked_hybrid_fft_product(row_count - 1U, row_workspace_stride,
            "Hybrid row workspace overflow"), row_bytes, "Hybrid row workspace overflow") > workspace_bytes)
        throw std::invalid_argument("Invalid hybrid FFT row batch workspace.");
    auto* const workspace = static_cast<unsigned char*>(device_workspace);
    auto* const spectrum = reinterpret_cast<float2*>(workspace);
    auto* const volterra_variances = reinterpret_cast<float*>(
        workspace + kHybridFftSpectrumBytes
    );
    using Row = PreparedRow<
        KernelPolicy,
        ModelPathPolicy,
        ProductPolicy,
        SchedulePolicy
    >;
    auto* const prepared_row = reinterpret_cast<Row*>(
        workspace + kHybridFftPreparedRowOffset
    );
    auto* const convolutions = reinterpret_cast<float2*>(
        workspace + kHybridFftConvolutionOffset
    );
    auto* const partial_moments = reinterpret_cast<PartialMoments*>(
        workspace + kHybridFftConvolutionOffset
            + hybrid_fft_convolution_bytes(step_count, path_chunk_size)
    );
    const std::uint32_t device_step_count =
        static_cast<std::uint32_t>(step_count);

#if AI_FACTORY_VOLTERRA_DIRECT_MAX_STEP_COUNT > 0
    if (step_count <= kDirectMaximumStepCount) {
        launch_direct<
            KernelPolicy,
            ModelPathPolicy,
            ProductPolicy,
            SchedulePolicy
        >(
            device_models,
            device_products,
            product_count,
            construction,
            result_index,
            monte_carlo_paths_per_price,
            device_step_count,
            time_configuration,
            path_chunk_size,
            volterra_variances,
            prepared_row,
            partial_moments,
            base_seed,
            device_prices,
            device_standard_errors,
            diagnostic_name,
            diagnostic_variant, consumer, row_count, row_workspace_stride
        );
    } else
#endif
    tuning::dispatch_hybrid_fft_specialization<kMaximumHybridFftLength>(
        device_step_count,
        [&]<typename Specialization>() {
            launch_fft_length<
                KernelPolicy,
                ModelPathPolicy,
                ProductPolicy,
                SchedulePolicy,
                Specialization::kLength,
                Specialization::kPricingElementsPerThread,
                Specialization::kPricingFftsPerBlock
            >(
                device_models,
                device_products,
                product_count,
                construction,
                result_index,
                monte_carlo_paths_per_price,
                device_step_count,
                time_configuration,
                path_chunk_size,
                spectrum,
                volterra_variances,
                prepared_row,
                convolutions,
                partial_moments,
                base_seed,
                device_prices,
                device_standard_errors,
                diagnostic_name,
                diagnostic_variant, consumer, row_count, row_workspace_stride
            );
        }
    );
}

template<typename KernelPolicy, typename ModelPathPolicy,
         typename ProductPolicy, typename SchedulePolicy>
void launch_pricing_cuda(
    const typename ModelPathPolicy::Parameters* device_models,
    std::size_t model_count,
    const typename ProductPolicy::ProductParameters* device_products,
    std::size_t product_count,
    PriceConstruction construction,
    std::size_t result_count,
    std::size_t result_index,
    std::size_t monte_carlo_paths_per_price,
    HybridTimeConfiguration time_configuration,
    std::size_t step_count,
    std::size_t path_chunk_size,
    void* device_workspace,
    std::size_t workspace_bytes,
    std::uint64_t base_seed,
    float* device_prices,
    float* device_standard_errors,
    const char* diagnostic_name,
    const char* diagnostic_variant,
    std::size_t row_count = 1U
) {
    const auto stride = required_hybrid_fft_workspace_bytes(step_count, monte_carlo_paths_per_price, path_chunk_size);
    launch_path_pipeline_cuda<KernelPolicy, ModelPathPolicy, ProductPolicy, SchedulePolicy>(
        device_models, model_count, device_products, product_count, construction,
        result_count, result_index, monte_carlo_paths_per_price, time_configuration,
        step_count, path_chunk_size, device_workspace, workspace_bytes, base_seed,
        device_prices, device_standard_errors, diagnostic_name, diagnostic_variant,
        PricePathConsumer{row_count, stride}, row_count, stride);
}

}  // namespace ai_factory::workbench::volterra::hybrid_fft

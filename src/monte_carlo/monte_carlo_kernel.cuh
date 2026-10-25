// Generic one-block-per-price Monte Carlo execution layer.
#pragma once

#include "cuda/check_cuda.cuh"
#include "cuda/cuda_kernel_diagnostics.cuh"
#include "monte_carlo/concepts.cuh"
#include "monte_carlo/reductions.cuh"
#include "pricing_rows/result_index.cuh"
#include "schedule/schedule.cuh"

#include <cuda_runtime.h>

#include <cstddef>
#include <cstdint>
#include <stdexcept>

namespace ai_factory::workbench::monte_carlo {

template<ScalarMonteCarloPricingPolicy PricingPolicy>
__global__ void monte_carlo_price_kernel(
    typename PricingPolicy::DeviceInputs inputs,
    std::size_t result_offset,
    std::size_t launch_result_count,
    std::size_t monte_carlo_paths_per_price,
    typename PricingPolicy::Schedule::TimeConfiguration time_configuration,
    std::uint64_t base_seed,
    float* __restrict__ prices,
    float* __restrict__ standard_errors
) {
    static_assert(
        sizeof(typename PricingPolicy::PreparedRow)
            <= kMaximumSharedPreparedRowBytes,
        "Monte Carlo PreparedRow exceeds the 2048-byte shared-memory "
        "budget; store a compact ScheduleView instead of embedding the "
        "complete runtime calendar."
    );
    __shared__ typename PricingPolicy::PreparedRow prepared;
    __shared__ philox::PhiloxKey key;

    for (std::size_t launch_index = blockIdx.x;
         launch_index < launch_result_count;
         launch_index += gridDim.x) {
        const std::size_t result_index = result_offset + launch_index;
        if (threadIdx.x == 0U) {
            prepared = inputs.template prepare_row<PricingPolicy>(
                result_index,
                time_configuration
            );
            const auto candidate_index = [&] {
                if constexpr (requires { inputs.source_row(result_index); })
                    return inputs.source_row(result_index);
                else return result_index;
            }();
            key = philox::make_key(base_seed + candidate_index);
        }
        __syncthreads();

        double sum = 0.0;
        double sumsq = 0.0;
        for (std::size_t path = threadIdx.x;
             path < monte_carlo_paths_per_price;
            path += blockDim.x) {
            const double value = static_cast<double>(
                PricingPolicy::evaluate_path(prepared, key, path)
            );
            sum += value;
            sumsq += value * value;
        }

        const reductions::MomentSums total =
            reductions::reduce_block(sum, sumsq);
        if (threadIdx.x == 0U) {
            double price = 0.0;
            double standard_error = 0.0;
            reductions::compute_statistics(
                total,
                monte_carlo_paths_per_price,
                price,
                standard_error,
                monte_carlo_paths_per_price / blockDim.x
                    + (monte_carlo_paths_per_price % blockDim.x != 0U)
            );
            prices[result_index] = static_cast<float>(price);
            standard_errors[result_index] =
                static_cast<float>(standard_error);
        }
        __syncthreads();
    }
}

template<MonteCarloLaunchPolicy PricingPolicy>
inline void validate_monte_carlo_launch(
    const typename PricingPolicy::DeviceInputs& inputs,
    const typename PricingPolicy::HostInputs& host_inputs,
    std::size_t result_count,
    std::size_t result_offset,
    std::size_t launch_result_count,
    std::size_t monte_carlo_paths_per_price,
    const typename PricingPolicy::Schedule::TimeConfiguration&
        time_configuration,
    unsigned int threads_per_block,
    std::size_t block_count,
    std::uint64_t base_seed,
    const float* device_prices,
    const float* device_standard_errors
) {
    static_assert(
        sizeof(typename PricingPolicy::PreparedRow)
            <= kMaximumSharedPreparedRowBytes,
        "Monte Carlo PreparedRow exceeds the 2048-byte shared-memory "
        "budget; store a compact ScheduleView instead of embedding the "
        "complete runtime calendar."
    );
    inputs.validate(result_count);
    host_inputs.validate(result_count, time_configuration);
    validate_device_pointer(device_prices, "device_prices");
    validate_device_pointer(
        device_standard_errors,
        "device_standard_errors"
    );

    if (result_offset >= result_count
        || launch_result_count == 0U
        || launch_result_count > result_count - result_offset) {
        throw std::invalid_argument(
            "The Monte Carlo launch batch exceeds the result array."
        );
    }

    validate_monte_carlo_path_count(monte_carlo_paths_per_price);
    simulation::validate_time_configuration(time_configuration);
    validate_reduction_block_size(threads_per_block);
    validate_block_count(launch_result_count, block_count);
    validate_grid_x_size(block_count);
    if constexpr (requires { inputs.source_row_count(); })
        validate_row_seed_range(inputs.source_row_count(), base_seed);
    else
        validate_row_seed_range(result_count, base_seed);
}

template<ScalarMonteCarloPricingPolicy PricingPolicy>
inline void launch_monte_carlo_cuda(
    const typename PricingPolicy::DeviceInputs& inputs,
    const typename PricingPolicy::HostInputs& host_inputs,
    std::size_t result_count,
    std::size_t result_offset,
    std::size_t launch_result_count,
    std::size_t monte_carlo_paths_per_price,
    const typename PricingPolicy::Schedule::TimeConfiguration&
        time_configuration,
    unsigned int threads_per_block,
    std::size_t block_count,
    std::uint64_t base_seed,
    float* device_prices,
    float* device_standard_errors,
    const char* diagnostic_name,
    const char* diagnostic_variant,
    const char* operation_name
) {
    validate_monte_carlo_launch<PricingPolicy>(
        inputs,
        host_inputs,
        result_count,
        result_offset,
        launch_result_count,
        monte_carlo_paths_per_price,
        time_configuration,
        threads_per_block,
        block_count,
        base_seed,
        device_prices,
        device_standard_errors
    );

    const std::size_t shared_bytes =
        2U * (threads_per_block / 32U) * sizeof(double);
    int active_blocks_per_multiprocessor = 0;
    check_cuda(
        cudaOccupancyMaxActiveBlocksPerMultiprocessor(
            &active_blocks_per_multiprocessor,
            monte_carlo_price_kernel<PricingPolicy>,
            static_cast<int>(threads_per_block),
            shared_bytes
        ),
        operation_name
    );
    if (active_blocks_per_multiprocessor == 0) {
        throw std::invalid_argument(
            "The Monte Carlo kernel cannot launch one block per SM."
        );
    }

    report_cuda_kernel_launch_if_enabled(
        diagnostic_name,
        diagnostic_variant,
        monte_carlo_price_kernel<PricingPolicy>,
        dim3(static_cast<unsigned int>(block_count)),
        dim3(threads_per_block),
        shared_bytes
    );
    monte_carlo_price_kernel<PricingPolicy><<<
        static_cast<unsigned int>(block_count),
        threads_per_block,
        shared_bytes
    >>>(
        inputs,
        result_offset,
        launch_result_count,
        monte_carlo_paths_per_price,
        time_configuration,
        base_seed,
        device_prices,
        device_standard_errors
    );
    check_cuda(cudaGetLastError(), operation_name);
}

}  // namespace ai_factory::workbench::monte_carlo

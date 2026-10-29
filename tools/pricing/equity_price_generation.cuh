// Generic offline assembly for generated equity price recipes.
#pragma once

#include "volterra/hybrid_fft_workspace.cuh"

#include "datasets/validation.hpp"
#include "equity/spot_relative_product.hpp"
#include "pricing_rows/price_construction.cuh"
#include "pricing_rows/result_index.cuh"
#include "tools/cuda/pricing_runner.cuh"
#include "tools/cuda/pricing_launch_plan.hpp"
#include "tools/cuda/monte_carlo_generation_checkpoint.cuh"
#include "tools/cuda/generation_progress.hpp"
#include "tools/datasets/price_dataset.hpp"

#include <nlohmann/json.hpp>

#include <algorithm>
#include <cmath>
#include <cstddef>
#include <cstdint>
#include <filesystem>
#include <functional>
#include <limits>
#include <stdexcept>
#include <string>
#include <utility>
#include <vector>

namespace ai_factory::workbench::offline::pricing {

struct EquityPriceRecipe {
    std::filesystem::path model_dataset_path;
    std::filesystem::path product_dataset_path;
    std::filesystem::path dataset_path;
    std::filesystem::path catalog_path;
    std::string url;
    std::string numerical_method;
    PriceConstruction construction = PriceConstruction::Aligned;
};

struct BatchedMonteCarloProfile {
    std::size_t paths_per_price = 0U;
    std::size_t results_per_launch = 0U;
    std::size_t block_count_limit = 0U;
    unsigned int threads_per_block = 0U;
    std::uint64_t seed = 0U;
    std::string delta_t_description;
    nlohmann::ordered_json execution_metadata =
        nlohmann::ordered_json::object();
    cuda_tuning::PricingIdentity identity;
    std::size_t blocks_per_price = 1U;
};

struct VolterraMonteCarloProfile {
    std::size_t paths_per_price = 0U;
    float day_fraction = 0.0f;
    float target_dt = 0.0f;
    std::size_t path_chunk_size = 0U;
    std::uint64_t seed = 0U;
    std::string delta_t_description;
    cuda_tuning::PricingIdentity identity{cuda_tuning::PricingFamily::rough_fft, {}, {}, {}};
    std::size_t rows_per_launch = 1U;
};

struct AnalyticalProfile {
    float day_fraction = 0.0f;
    unsigned int threads_per_block = 0U;
    std::uint32_t simulation_steps_per_day = 0U;
    cuda_tuning::PricingIdentity identity{cuda_tuning::PricingFamily::closed_form, {}, {}, {}};
};

struct BatchedLaunchContext {
    PriceConstruction construction;
    std::size_t result_count;
    std::size_t result_offset;
    std::size_t launch_result_count;
    std::size_t paths_per_price;
    std::size_t block_count;
    std::uint64_t seed;
};

struct AnalyticalLaunchContext {
    PriceConstruction construction;
    std::size_t result_count;
    std::size_t result_offset;
    std::size_t launch_result_count;
    float day_fraction;
    std::uint32_t simulation_steps_per_day;
    unsigned int threads_per_block;
    std::size_t block_count;
};

struct VolterraLaunchContext {
    PriceConstruction construction;
    std::size_t result_count;
    std::size_t result_index;
    std::size_t paths_per_price;
    float day_fraction;
    float target_dt;
    std::size_t step_count;
    std::size_t path_chunk_size;
    std::uint64_t seed;
    std::size_t row_count = 1U;
};

struct MonteCarloExecution {
    cuda::MonteCarloRun run;
    nlohmann::ordered_json execution_metadata;
};

struct AnalyticalExecution {
    cuda::AnalyticalRun run;
    nlohmann::ordered_json execution_metadata;
};

inline void attach_checkpoint_metadata(
    nlohmann::ordered_json& metadata,
    const cuda::MonteCarloGenerationCheckpoint& checkpoint
) {
    if (!checkpoint.enabled()) return;
    metadata["checkpoint"] = {
        {"schema_version", 1},
        {"resumed_prices", checkpoint.resumed_prices()},
        {"timing_scope", "current process attempt"},
    };
}

inline std::size_t warmup_row_count(
    std::size_t model_count,
    std::size_t product_count
) {
    return std::min<std::size_t>(
        64U,
        std::min(model_count, product_count)
    );
}

inline std::uint32_t rounded_volterra_step_count(
    std::uint32_t maturity_days,
    float day_fraction,
    float target_dt
) {
    if (maturity_days == 0U
        || !std::isfinite(day_fraction)
        || !(day_fraction > 0.0f)
        || !std::isfinite(target_dt)
        || !(target_dt > 0.0f)) {
        throw std::invalid_argument(
            "A Volterra price recipe requires positive finite time inputs."
        );
    }
    const double rounded = std::max(
        1.0,
        std::floor(
            static_cast<double>(maturity_days)
                * static_cast<double>(day_fraction)
                / static_cast<double>(target_dt)
            + 0.5
        )
    );
    if (rounded > static_cast<double>(
            std::numeric_limits<std::uint32_t>::max()
        )) {
        throw std::overflow_error(
            "The Volterra recipe step count exceeds uint32_t."
        );
    }
    return static_cast<std::uint32_t>(rounded);
}

inline cuda_tuning::PricingLaunchPlan monte_carlo_launch_plan(
    const BatchedMonteCarloProfile& profile, std::size_t result_count
) {
    auto settings = cuda_tuning::pricing_profile(profile.identity);
    settings.threads_per_block = profile.threads_per_block;
    settings.prices_per_launch = profile.results_per_launch;
    settings.block_count_limit = profile.block_count_limit;
    return cuda_tuning::make_pricing_launch_plan(
        profile.identity, result_count, profile.paths_per_price, settings
    );
}

template<class Models, class Products, class Launcher>
MonteCarloExecution execute_batched_monte_carlo(
    const Models& models,
    const Products& products,
    PriceConstruction construction,
    const BatchedMonteCarloProfile& profile,
    Launcher&& launcher
) {
    const std::size_t result_count = price_row_count(
        models.size(), products.size(), construction
    );
    const auto plan = monte_carlo_launch_plan(profile, result_count);
    const std::size_t launch_count = plan.price_launch_count();
    const std::size_t maximum_block_count = plan.blocks_for(plan.prices_per_launch);
    const std::size_t warmup_count = std::min(
        warmup_row_count(models.size(), products.size()), plan.prices_per_launch
    );
    cuda::MonteCarloGenerationCheckpoint checkpoint(result_count);
    cuda::GenerationProgress progress(
        result_count, checkpoint.completed_prices()
    );

    auto run = cuda::run_monte_carlo(
        cuda::inputs(models, products),
        result_count,
        [&](auto& execution) {
            const BatchedLaunchContext context{
                PriceConstruction::Aligned,
                warmup_count,
                0U,
                warmup_count,
                profile.paths_per_price,
                plan.blocks_for(warmup_count),
                profile.seed,
            };
            std::invoke(
                launcher,
                execution.template input<0U>(),
                warmup_count,
                products.data(),
                execution.template input<1U>(),
                warmup_count,
                context,
                execution.prices(),
                execution.standard_errors()
            );
        },
        [&](auto& execution) {
            for (std::size_t offset = checkpoint.completed_prices();
                 offset < result_count;
                 /* Advance by the actual final batch size, without overflow. */) {
                const std::size_t count = plan.price_count_at(offset);
                const BatchedLaunchContext context{
                    construction,
                    result_count,
                    offset,
                    count,
                    profile.paths_per_price,
                    plan.blocks_for(count),
                    profile.seed,
                };
                checkpoint.start_batch();
                std::invoke(
                    launcher,
                    execution.template input<0U>(),
                    models.size(),
                    products.data(),
                    execution.template input<1U>(),
                    products.size(),
                    context,
                    execution.prices(),
                    execution.standard_errors()
                );
                if (checkpoint.enabled()) {
                    checkpoint.commit(execution, offset, count);
                    progress.record_host_progress(offset + count);
                } else {
                    progress.record_cuda_progress(offset + count);
                }
                offset += count;
            }
        }
    );
    checkpoint.restore(run);
    checkpoint.restore_kernel_seconds(run);
    progress.complete();

    nlohmann::ordered_json metadata = profile.execution_metadata;
    metadata["block_count"] = maximum_block_count;
    metadata["threads_per_block"] = profile.threads_per_block;
    metadata["kernel_launch_count"] = launch_count;
    metadata["maximum_prices_per_block"] = cuda_tuning::ceiling_divide(
        plan.prices_per_launch, maximum_block_count
    );
    metadata["launch_plan"] = cuda_tuning::pricing_launch_metadata(plan);
    metadata["tuning_profile"] = cuda_tuning::metadata(
        metadata.contains("factor_count")
            ? "rough_n_factor_pricing"
            : "markovian_pricing"
    );
    attach_checkpoint_metadata(metadata, checkpoint);
    return {std::move(run), std::move(metadata)};
}

template<class Models, class Prepared, class Products, class Launcher>
MonteCarloExecution execute_prepared_batched_monte_carlo(
    const Models& models,
    const Prepared& prepared,
    const Products& products,
    PriceConstruction construction,
    const BatchedMonteCarloProfile& profile,
    Launcher&& launcher
) {
    const std::size_t result_count = price_row_count(
        models.size(), products.size(), construction
    );
    const auto plan = monte_carlo_launch_plan(profile, result_count);
    const std::size_t launch_count = plan.price_launch_count();
    const std::size_t maximum_block_count = plan.blocks_for(plan.prices_per_launch);
    const std::size_t warmup_count = std::min(
        warmup_row_count(models.size(), products.size()), plan.prices_per_launch
    );
    cuda::MonteCarloGenerationCheckpoint checkpoint(result_count);
    cuda::GenerationProgress progress(
        result_count, checkpoint.completed_prices()
    );

    auto run = cuda::run_monte_carlo(
        cuda::inputs(models, prepared, products),
        result_count,
        [&](auto& execution) {
            const BatchedLaunchContext context{
                PriceConstruction::Aligned,
                warmup_count,
                0U,
                warmup_count,
                profile.paths_per_price,
                plan.blocks_for(warmup_count),
                profile.seed,
            };
            std::invoke(
                launcher,
                execution.template input<0U>(),
                warmup_count,
                execution.template input<1U>(),
                warmup_count,
                products.data(),
                execution.template input<2U>(),
                warmup_count,
                context,
                execution.prices(),
                execution.standard_errors()
            );
        },
        [&](auto& execution) {
            for (std::size_t offset = checkpoint.completed_prices();
                 offset < result_count;
                 /* Advance by the actual final batch size, without overflow. */) {
                const std::size_t count = plan.price_count_at(offset);
                const BatchedLaunchContext context{
                    construction,
                    result_count,
                    offset,
                    count,
                    profile.paths_per_price,
                    plan.blocks_for(count),
                    profile.seed,
                };
                checkpoint.start_batch();
                std::invoke(
                    launcher,
                    execution.template input<0U>(),
                    models.size(),
                    execution.template input<1U>(),
                    prepared.size(),
                    products.data(),
                    execution.template input<2U>(),
                    products.size(),
                    context,
                    execution.prices(),
                    execution.standard_errors()
                );
                if (checkpoint.enabled()) {
                    checkpoint.commit(execution, offset, count);
                    progress.record_host_progress(offset + count);
                } else {
                    progress.record_cuda_progress(offset + count);
                }
                offset += count;
            }
        }
    );
    checkpoint.restore(run);
    checkpoint.restore_kernel_seconds(run);
    progress.complete();

    nlohmann::ordered_json metadata = profile.execution_metadata;
    metadata["block_count"] = maximum_block_count;
    metadata["threads_per_block"] = profile.threads_per_block;
    metadata["kernel_launch_count"] = launch_count;
    metadata["maximum_prices_per_block"] = cuda_tuning::ceiling_divide(
        plan.prices_per_launch, maximum_block_count
    );
    metadata["launch_plan"] = cuda_tuning::pricing_launch_metadata(plan);
    metadata["tuning_profile"] = cuda_tuning::metadata(
        "rough_n_factor_pricing"
    );
    attach_checkpoint_metadata(metadata, checkpoint);
    return {std::move(run), std::move(metadata)};
}

template<class Models, class Products, class WorkspacePlanner, class Launcher>
MonteCarloExecution execute_volterra_monte_carlo(
    const Models& models,
    const Products& products,
    PriceConstruction construction,
    const VolterraMonteCarloProfile& profile,
    WorkspacePlanner&& workspace_planner,
    Launcher&& launcher
) {
    const std::size_t result_count = price_row_count(
        models.size(), products.size(), construction
    );
    std::size_t maximum_step_count = 1U;
    for (const auto& product : products) {
        maximum_step_count = std::max<std::size_t>(
            maximum_step_count,
            rounded_volterra_step_count(
                product.maturity_days,
                profile.day_fraction,
                profile.target_dt
            )
        );
    }
    auto settings = cuda_tuning::pricing_profile(profile.identity);
    settings.path_chunk_size = profile.path_chunk_size;
    const auto plan = cuda_tuning::make_pricing_launch_plan(
        profile.identity, result_count, profile.paths_per_price, settings
    );
    if (profile.rows_per_launch == 0U || profile.rows_per_launch > 65535U)
        throw std::invalid_argument("Invalid Volterra rows_per_launch.");
    const auto workspace = std::invoke(
        workspace_planner,
        maximum_step_count,
        profile.paths_per_price,
        profile.path_chunk_size
    );
    const auto resident_rows = std::min(profile.rows_per_launch, result_count);
    const auto workspace_bytes = volterra::checked_hybrid_fft_product(
        workspace.workspace_bytes, resident_rows, "Volterra row workspace overflow");
    std::size_t submitted_batches = 0U;
    cuda::MonteCarloGenerationCheckpoint checkpoint(result_count);
    cuda::GenerationProgress progress(
        result_count, checkpoint.completed_prices()
    );

    auto invoke_row = [&](auto& execution, std::size_t result_index, std::size_t row_count = 1U) {
        const ModelProductIndices indices = decode_model_product_result_index(
            result_index,
            products.size(),
            construction
        );
        const VolterraLaunchContext context{
            construction,
            result_count,
            result_index,
            profile.paths_per_price,
            profile.day_fraction,
            profile.target_dt,
            rounded_volterra_step_count(
                products[indices.product_index].maturity_days,
                profile.day_fraction,
                profile.target_dt
            ),
            profile.path_chunk_size,
            profile.seed, row_count,
        };
        std::invoke(
            launcher,
            execution.template input<0U>(),
            models.size(),
            execution.template input<1U>(),
            products.size(),
            context,
            execution.workspace(),
            execution.workspace_bytes(),
            execution.prices(),
            execution.standard_errors()
        );
    };

    auto run = cuda::run_monte_carlo_with_workspace(
        cuda::inputs(models, products),
        result_count,
        workspace_bytes,
        [&](auto& execution) { invoke_row(execution, 0U); },
        [&](auto& execution) {
            for (std::size_t index = checkpoint.completed_prices(); index < result_count;) {
                // Contiguous rows only: retain each row's native FFT and calendar.
                const auto steps_at = [&](std::size_t row) {
                    const auto id = decode_model_product_result_index(row, products.size(), construction);
                    return rounded_volterra_step_count(products[id.product_index].maturity_days,
                        profile.day_fraction, profile.target_dt);
                };
                const auto steps = steps_at(index);
                std::size_t count = 1U;
                while (count < profile.rows_per_launch && index + count < result_count
                       && steps_at(index + count) == steps) ++count;
                checkpoint.start_batch();
                invoke_row(execution, index, count);
                ++submitted_batches;
                if (checkpoint.enabled()) {
                    checkpoint.commit(execution, index, count);
                    progress.record_host_progress(index + count);
                } else {
                    progress.record_cuda_progress(index + count);
                }
                index += count;
            }
        }
    );
    checkpoint.restore(run);
    checkpoint.restore_kernel_seconds(run);
    progress.complete();

    nlohmann::ordered_json metadata{
            {"path_chunk_size", profile.path_chunk_size},
            {
                "chunks_per_price",
                cuda_tuning::ceiling_divide(profile.paths_per_price, profile.path_chunk_size)
            },
            {"maximum_step_count", maximum_step_count},
            {"workspace_bytes", workspace_bytes},
            {"rows_per_launch", resident_rows},
            {"price_submission_count", submitted_batches},
            {"launch_plan", cuda_tuning::pricing_launch_metadata(plan)},
            {"tuning_profile", cuda_tuning::metadata("volterra_fft_pricing")},
    };
    attach_checkpoint_metadata(metadata, checkpoint);
    return {std::move(run), std::move(metadata)};
}

template<class Models, class Products, class Launcher>
AnalyticalExecution execute_analytical(
    const Models& models,
    const Products& products,
    PriceConstruction construction,
    const AnalyticalProfile& profile,
    Launcher&& launcher
) {
    const std::size_t result_count = price_row_count(
        models.size(), products.size(), construction
    );
    const std::size_t warmup_count = warmup_row_count(
        models.size(), products.size()
    );
    auto settings = cuda_tuning::pricing_profile(profile.identity);
    settings.threads_per_block = profile.threads_per_block;
    const auto plan = cuda_tuning::make_pricing_launch_plan(profile.identity, result_count, 0U, settings);
    const auto blocks_for = [&](std::size_t count) { return plan.blocks_for(count); };
    auto run = cuda::run_analytical(
        cuda::inputs(models, products),
        result_count,
        [&](auto& execution) {
            const AnalyticalLaunchContext context{
                PriceConstruction::Aligned,
                warmup_count,
                0U,
                warmup_count,
                profile.day_fraction,
                profile.simulation_steps_per_day,
                profile.threads_per_block,
                blocks_for(warmup_count),
            };
            std::invoke(
                launcher,
                execution.template input<0U>(),
                warmup_count,
                execution.template input<1U>(),
                warmup_count,
                context,
                execution.prices()
            );
        },
        [&](auto& execution) {
            const AnalyticalLaunchContext context{
                construction,
                result_count,
                0U,
                result_count,
                profile.day_fraction,
                profile.simulation_steps_per_day,
                profile.threads_per_block,
                blocks_for(result_count),
            };
            std::invoke(
                launcher,
                execution.template input<0U>(),
                models.size(),
                execution.template input<1U>(),
                products.size(),
                context,
                execution.prices()
            );
        }
    );
    nlohmann::ordered_json metadata{
        {"block_count", blocks_for(result_count)},
        {"threads_per_block", profile.threads_per_block},
        {"kernel_launch_count", 1U},
        {"work_distribution", "one price per thread"},
        {"tuning_profile", cuda_tuning::metadata("analytical_pricing")},
        {"launch_plan", cuda_tuning::pricing_launch_metadata(plan)},
    };
    if (profile.simulation_steps_per_day != 0U) {
        metadata["simulation_steps_per_day"] =
            profile.simulation_steps_per_day;
    }
    return {std::move(run), std::move(metadata)};
}

template<class ModelLoader, class ProductLoader, class Executor>
int generate_monte_carlo_equity_price_dataset(
    const EquityPriceRecipe& recipe,
    const BatchedMonteCarloProfile& profile,
    ModelLoader&& model_loader,
    ProductLoader&& product_loader,
    Executor&& executor
) {
    const auto models = std::invoke(
        model_loader, recipe.model_dataset_path
    );
    const auto products = std::invoke(
        product_loader, recipe.product_dataset_path
    );
    equity::spot_relative::validate_resolved_rows(
        models, products, recipe.construction
    );
    MonteCarloExecution execution = std::invoke(
        executor, models, products, recipe.construction, profile
    );
    execution.execution_metadata["product_spot_levels"] =
        "quote ratio times central model spot; frozen for sensitivities";
    datasets::write_monte_carlo_price_dataset(
        recipe.model_dataset_path,
        recipe.product_dataset_path,
        recipe.construction,
        execution.run.prices,
        execution.run.standard_errors,
        "Philox",
        recipe.dataset_path,
        recipe.catalog_path,
        recipe.url,
        recipe.numerical_method,
        profile.paths_per_price,
        profile.delta_t_description,
        execution.execution_metadata,
        nlohmann::ordered_json::object(),
        profile.seed,
        execution.run.wall_seconds,
        execution.run.kernel_seconds
    );
    datasets::validate_price_dataset_file(recipe.dataset_path);
    return 0;
}

template<class ModelLoader, class ProductLoader, class Executor>
int generate_volterra_equity_price_dataset(
    const EquityPriceRecipe& recipe,
    const VolterraMonteCarloProfile& profile,
    ModelLoader&& model_loader,
    ProductLoader&& product_loader,
    Executor&& executor
) {
    const auto models = std::invoke(
        model_loader, recipe.model_dataset_path
    );
    const auto products = std::invoke(
        product_loader, recipe.product_dataset_path
    );
    equity::spot_relative::validate_resolved_rows(
        models, products, recipe.construction
    );
    MonteCarloExecution execution = std::invoke(
        executor, models, products, recipe.construction, profile
    );
    execution.execution_metadata["product_spot_levels"] =
        "quote ratio times central model spot; frozen for sensitivities";
    datasets::write_monte_carlo_price_dataset(
        recipe.model_dataset_path,
        recipe.product_dataset_path,
        recipe.construction,
        execution.run.prices,
        execution.run.standard_errors,
        "Philox",
        recipe.dataset_path,
        recipe.catalog_path,
        recipe.url,
        recipe.numerical_method,
        profile.paths_per_price,
        profile.delta_t_description,
        execution.execution_metadata,
        nlohmann::ordered_json::object(),
        profile.seed,
        execution.run.wall_seconds,
        execution.run.kernel_seconds
    );
    datasets::validate_price_dataset_file(recipe.dataset_path);
    return 0;
}

template<class ModelLoader, class ProductLoader, class Executor>
int generate_analytical_equity_price_dataset(
    const EquityPriceRecipe& recipe,
    const AnalyticalProfile& profile,
    ModelLoader&& model_loader,
    ProductLoader&& product_loader,
    Executor&& executor
) {
    const auto models = std::invoke(
        model_loader, recipe.model_dataset_path
    );
    const auto products = std::invoke(
        product_loader, recipe.product_dataset_path
    );
    equity::spot_relative::validate_resolved_rows(
        models, products, recipe.construction
    );
    AnalyticalExecution execution = std::invoke(
        executor, models, products, recipe.construction, profile
    );
    execution.execution_metadata["product_spot_levels"] =
        "quote ratio times central model spot";
    datasets::write_analytical_price_dataset(
        recipe.model_dataset_path,
        recipe.product_dataset_path,
        recipe.construction,
        execution.run.prices,
        recipe.dataset_path,
        recipe.catalog_path,
        recipe.url,
        recipe.numerical_method,
        execution.execution_metadata,
        execution.run.wall_seconds,
        execution.run.kernel_seconds
    );
    datasets::validate_price_dataset_file(recipe.dataset_path);
    return 0;
}

}  // namespace ai_factory::workbench::offline::pricing

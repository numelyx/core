/**
 * @file numelyx_core_optimizer.c
 * @brief Generic numerical optimization routines and result handling.
 *
 * @details This file belongs to Numerus's internal C implementation. Its
 * declarations and behavior are coordinated with the focused headers in the
 * same subsystem; changes should preserve their documented ownership,
 * validation, and error-reporting contracts.
 */

#include "numelyx_core_optimizer.h"
#include "numelyx_core_size.h"
#include "numelyx_core_lifetime.h"

#include <float.h>
#include <math.h>
#include <stdlib.h>
#include <string.h>

#if defined(NUMERUS_OPTIMIZER_TEST_ALLOCATOR)
void *numelyx_core_optimizer_test_alloc(size_t size);
void numelyx_core_optimizer_test_free(void *pointer);
# define numelyx_core_optimizer_alloc(size) numelyx_core_optimizer_test_alloc(size)
# define numelyx_core_optimizer_free(pointer) numelyx_core_optimizer_test_free(pointer)
#else
# define numelyx_core_optimizer_alloc(size) malloc(size)
# define numelyx_core_optimizer_free(pointer) free(pointer)
#endif

#define NUMERUS_OPTIMIZER_ARMIJO_CONSTANT 1e-4
#define NUMERUS_OPTIMIZER_BACKTRACKING_RATIO 0.5

struct numelyx_core_optimizer_result {
    numelyx_core_lifetime lifetime;
    size_t parameter_count;
    double *parameters;
    double objective_value;
    bool objective_value_valid;
    size_t iterations;
    size_t objective_evaluations;
    size_t gradient_evaluations;
    numelyx_core_optimizer_termination termination;
};

static void optimizer_result_destroy_final(void *object);

typedef enum {
    OBJECTIVE_EVALUATION_OK = 0,
    OBJECTIVE_EVALUATION_CALLBACK_FAILED,
    OBJECTIVE_EVALUATION_NON_FINITE
} objective_evaluation_status;

static void numelyx_core_optimizer_reset_identity(double *matrix, size_t size)
{
    size_t row;
    size_t column;

    for (row = 0; row < size; row++) {
        for (column = 0; column < size; column++) {
            matrix[row * size + column] = row == column ? 1.0 : 0.0;
        }
    }
}

static bool numelyx_core_optimizer_options_are_valid(
    const numelyx_core_optimizer_options *options
)
{
    if (options == NULL ||
        options->max_iterations == 0 ||
        options->max_line_search_iterations == 0) {
        return false;
    }

    if (!isfinite(options->gradient_tolerance) ||
        !isfinite(options->minimum_step) ||
        !isfinite(options->step_tolerance) ||
        !isfinite(options->initial_step) ||
        !isfinite(options->finite_difference_relative_step)) {
        return false;
    }

    return options->gradient_tolerance > 0.0 &&
        options->minimum_step > 0.0 &&
        options->step_tolerance > 0.0 &&
        options->initial_step > 0.0 &&
        options->minimum_step <= options->initial_step &&
        options->finite_difference_relative_step > 0.0;
}

static objective_evaluation_status numelyx_core_optimizer_evaluate_objective(
    numelyx_core_objective_fn objective,
    const void *context,
    const double *parameters,
    size_t parameter_count,
    size_t *evaluation_count,
    double *value
)
{
    double evaluated_value;

    (*evaluation_count)++;
    if (!objective(parameters, parameter_count, context, &evaluated_value)) {
        return OBJECTIVE_EVALUATION_CALLBACK_FAILED;
    }
    if (!isfinite(evaluated_value)) {
        return OBJECTIVE_EVALUATION_NON_FINITE;
    }

    *value = evaluated_value;
    return OBJECTIVE_EVALUATION_OK;
}

static numelyx_core_optimizer_termination numelyx_core_optimizer_evaluate_gradient(
    numelyx_core_objective_fn objective,
    numelyx_core_gradient_fn gradient,
    const void *context,
    const double *parameters,
    size_t parameter_count,
    const numelyx_core_optimizer_options *options,
    numelyx_core_optimizer_result *result,
    double *gradient_values,
    double *temporary_parameters
)
{
    size_t index;

    result->gradient_evaluations++;

    if (gradient != NULL) {
        if (!gradient(
            parameters, parameter_count, context, gradient_values
        )) {
            return NUMERUS_OPTIMIZER_GRADIENT_CALLBACK_FAILED;
        }

        for (index = 0; index < parameter_count; index++) {
            if (!isfinite(gradient_values[index])) {
                return NUMERUS_OPTIMIZER_NON_FINITE_GRADIENT;
            }
        }
        return NUMERUS_OPTIMIZER_CONVERGED_GRADIENT;
    }

    /* If no gradient callback is supplied, estimate each component with a
     * central difference. The step scales with max(1, |xᵢ|) so parameters
     * with different magnitudes are not all perturbed by the same absolute
     * amount. Both callback evaluations are counted as objective evaluations.
     */
    for (index = 0; index < parameter_count; index++) {
        double step = options->finite_difference_relative_step *
            fmax(1.0, fabs(parameters[index]));
        double plus_value;
        double minus_value;
        objective_evaluation_status evaluation_status;

        if (!isfinite(step) || step <= 0.0) {
            return NUMERUS_OPTIMIZER_GRADIENT_EVALUATION_FAILED;
        }

        memcpy(
            temporary_parameters,
            parameters,
            parameter_count * sizeof(*temporary_parameters)
        );
        temporary_parameters[index] = parameters[index] + step;
        if (!isfinite(temporary_parameters[index]) ||
            temporary_parameters[index] == parameters[index]) {
            return NUMERUS_OPTIMIZER_GRADIENT_EVALUATION_FAILED;
        }

        evaluation_status = numelyx_core_optimizer_evaluate_objective(
            objective,
            context,
            temporary_parameters,
            parameter_count,
            &result->objective_evaluations,
            &plus_value
        );
        if (evaluation_status != OBJECTIVE_EVALUATION_OK) {
            return NUMERUS_OPTIMIZER_GRADIENT_EVALUATION_FAILED;
        }

        temporary_parameters[index] = parameters[index] - step;
        if (!isfinite(temporary_parameters[index]) ||
            temporary_parameters[index] == parameters[index]) {
            return NUMERUS_OPTIMIZER_GRADIENT_EVALUATION_FAILED;
        }

        evaluation_status = numelyx_core_optimizer_evaluate_objective(
            objective,
            context,
            temporary_parameters,
            parameter_count,
            &result->objective_evaluations,
            &minus_value
        );
        if (evaluation_status != OBJECTIVE_EVALUATION_OK) {
            return NUMERUS_OPTIMIZER_GRADIENT_EVALUATION_FAILED;
        }

        gradient_values[index] = (plus_value - minus_value) / (2.0 * step);
        if (!isfinite(gradient_values[index])) {
            return NUMERUS_OPTIMIZER_NON_FINITE_GRADIENT;
        }
    }

    return NUMERUS_OPTIMIZER_CONVERGED_GRADIENT;
}

static double numelyx_core_optimizer_gradient_norm(
    const double *gradient,
    size_t size
)
{
    size_t index;
    double norm = 0.0;

    for (index = 0; index < size; index++) {
        double magnitude = fabs(gradient[index]);
        if (magnitude > norm) {
            norm = magnitude;
        }
    }
    return norm;
}

static bool numelyx_core_optimizer_compute_direction(
    const double *inverse_hessian,
    const double *gradient,
    size_t size,
    double *direction,
    double *directional_derivative
)
{
    size_t row;
    size_t column;
    double derivative = 0.0;

    for (row = 0; row < size; row++) {
        double value = 0.0;

        for (column = 0; column < size; column++) {
            value += inverse_hessian[row * size + column] * gradient[column];
            if (!isfinite(value)) {
                return false;
            }
        }

        direction[row] = -value;
        if (!isfinite(direction[row])) {
            return false;
        }
        derivative += gradient[row] * direction[row];
        if (!isfinite(derivative)) {
            return false;
        }
    }

    *directional_derivative = derivative;
    return true;
}

static bool numelyx_core_optimizer_compute_steepest_descent(
    const double *gradient,
    size_t size,
    double *direction,
    double *directional_derivative
)
{
    size_t index;
    double derivative = 0.0;

    for (index = 0; index < size; index++) {
        direction[index] = -gradient[index];
        derivative -= gradient[index] * gradient[index];
        if (!isfinite(derivative)) {
            return false;
        }
    }

    *directional_derivative = derivative;
    return true;
}

static void numelyx_core_optimizer_update_inverse_hessian(
    double *inverse_hessian,
    double *next_inverse_hessian,
    const double *step_vector,
    const double *gradient_delta,
    double *hessian_gradient,
    size_t size
)
{
    size_t row;
    size_t column;
    double curvature = 0.0;
    double gradient_curvature = 0.0;
    double step_norm = 0.0;
    double gradient_delta_norm = 0.0;
    double threshold;
    double coefficient;
    double reciprocal_curvature;

    for (row = 0; row < size; row++) {
        curvature += gradient_delta[row] * step_vector[row];
        step_norm = hypot(step_norm, step_vector[row]);
        gradient_delta_norm = hypot(
            gradient_delta_norm, gradient_delta[row]
        );
    }

    /* BFGS requires positive curvature sᵀy. When round-off or a non-convex
     * local step makes that condition unreliable, reset the approximation to
     * identity instead of applying an unstable rank-two update.
     */
    threshold = sqrt(DBL_EPSILON) * step_norm * gradient_delta_norm;
    if (!isfinite(curvature) || !isfinite(threshold) ||
        curvature <= threshold || curvature <= 0.0) {
        numelyx_core_optimizer_reset_identity(inverse_hessian, size);
        return;
    }

    for (row = 0; row < size; row++) {
        double value = 0.0;

        for (column = 0; column < size; column++) {
            value += inverse_hessian[row * size + column] *
                gradient_delta[column];
            if (!isfinite(value)) {
                numelyx_core_optimizer_reset_identity(inverse_hessian, size);
                return;
            }
        }
        hessian_gradient[row] = value;
        gradient_curvature += gradient_delta[row] * value;
        if (!isfinite(gradient_curvature)) {
            numelyx_core_optimizer_reset_identity(inverse_hessian, size);
            return;
        }
    }

    if (gradient_curvature < 0.0) {
        numelyx_core_optimizer_reset_identity(inverse_hessian, size);
        return;
    }

    coefficient = (1.0 + gradient_curvature / curvature) / curvature;
    reciprocal_curvature = 1.0 / curvature;
    if (!isfinite(coefficient) || !isfinite(reciprocal_curvature)) {
        numelyx_core_optimizer_reset_identity(inverse_hessian, size);
        return;
    }

    for (row = 0; row < size; row++) {
        for (column = 0; column < size; column++) {
            double rank_one = coefficient *
                step_vector[row] * step_vector[column];
            double cross = reciprocal_curvature *
                (hessian_gradient[row] * step_vector[column] +
                 step_vector[row] * hessian_gradient[column]);
            double value = inverse_hessian[row * size + column] +
                rank_one - cross;

            if (!isfinite(rank_one) || !isfinite(cross) || !isfinite(value)) {
                numelyx_core_optimizer_reset_identity(inverse_hessian, size);
                return;
            }
            next_inverse_hessian[row * size + column] = value;
        }
    }

    memcpy(
        inverse_hessian,
        next_inverse_hessian,
        size * size * sizeof(*inverse_hessian)
    );
}


static bool optimizer_dot_product(
    const double *left, const double *right, size_t size, double *result
)
{
    size_t index;
    double value = 0.0;
    for (index = 0; index < size; index++) {
        value += left[index] * right[index];
        if (!isfinite(value)) return false;
    }
    *result = value;
    return true;
}

static bool optimizer_compute_lbfgs_direction(
    const double *gradient,
    size_t parameter_count,
    const double *s_history,
    const double *y_history,
    const double *rho_history,
    double *alpha_history,
    size_t history_count,
    double *workspace,
    double *direction,
    double *directional_derivative
)
{
    size_t index;
    double gamma = 1.0;
    double derivative;

    memcpy(workspace, gradient, parameter_count * sizeof(*workspace));

    index = history_count;
    while (index > 0) {
        size_t pair = --index;
        const double *s = s_history + pair * parameter_count;
        const double *y = y_history + pair * parameter_count;
        double dot;
        size_t component;

        if (!optimizer_dot_product(s, workspace, parameter_count, &dot))
            return false;
        alpha_history[pair] = rho_history[pair] * dot;
        if (!isfinite(alpha_history[pair])) return false;
        for (component = 0; component < parameter_count; component++) {
            workspace[component] -= alpha_history[pair] * y[component];
            if (!isfinite(workspace[component])) return false;
        }
    }

    if (history_count > 0) {
        size_t last = history_count - 1;
        const double *s = s_history + last * parameter_count;
        const double *y = y_history + last * parameter_count;
        double sy;
        double yy;
        if (optimizer_dot_product(s, y, parameter_count, &sy) &&
            optimizer_dot_product(y, y, parameter_count, &yy) &&
            sy > 0.0 && yy > 0.0) {
            double candidate = sy / yy;
            if (isfinite(candidate) && candidate > 0.0) gamma = candidate;
        }
    }

    for (index = 0; index < parameter_count; index++) {
        direction[index] = gamma * workspace[index];
        if (!isfinite(direction[index])) return false;
    }

    for (index = 0; index < history_count; index++) {
        const double *s = s_history + index * parameter_count;
        const double *y = y_history + index * parameter_count;
        double dot;
        double beta;
        size_t component;

        if (!optimizer_dot_product(y, direction, parameter_count, &dot))
            return false;
        beta = rho_history[index] * dot;
        if (!isfinite(beta)) return false;
        for (component = 0; component < parameter_count; component++) {
            direction[component] +=
                s[component] * (alpha_history[index] - beta);
            if (!isfinite(direction[component])) return false;
        }
    }

    derivative = 0.0;
    for (index = 0; index < parameter_count; index++) {
        direction[index] = -direction[index];
        derivative += gradient[index] * direction[index];
        if (!isfinite(direction[index]) || !isfinite(derivative))
            return false;
    }
    *directional_derivative = derivative;
    return true;
}

static void optimizer_update_lbfgs_history(
    const double *step,
    const double *gradient_delta,
    size_t parameter_count,
    size_t history_size,
    double *s_history,
    double *y_history,
    double *rho_history,
    size_t *history_count
)
{
    size_t index;
    double curvature;
    double step_norm = 0.0;
    double gradient_norm = 0.0;
    double threshold;

    if (!optimizer_dot_product(
            step, gradient_delta, parameter_count, &curvature)) return;
    for (index = 0; index < parameter_count; index++) {
        step_norm = hypot(step_norm, step[index]);
        gradient_norm = hypot(gradient_norm, gradient_delta[index]);
    }
    threshold = sqrt(DBL_EPSILON) * step_norm * gradient_norm;
    if (!isfinite(curvature) || !isfinite(threshold) ||
        curvature <= threshold || curvature <= 0.0) {
        return;
    }

    if (*history_count == history_size) {
        size_t pair_bytes = (history_size - 1) * parameter_count *
            sizeof(*s_history);
        if (pair_bytes > 0) {
            memmove(s_history, s_history + parameter_count, pair_bytes);
            memmove(y_history, y_history + parameter_count, pair_bytes);
        }
        if (history_size > 1) {
            memmove(rho_history, rho_history + 1,
                (history_size - 1) * sizeof(*rho_history));
        }
        (*history_count)--;
    }

    memcpy(
        s_history + (*history_count) * parameter_count,
        step, parameter_count * sizeof(*step)
    );
    memcpy(
        y_history + (*history_count) * parameter_count,
        gradient_delta, parameter_count * sizeof(*gradient_delta)
    );
    rho_history[*history_count] = 1.0 / curvature;
    if (!isfinite(rho_history[*history_count])) return;
    (*history_count)++;
}

static void numelyx_core_optimizer_release_workspace(
    double *gradient,
    double *new_gradient,
    double *direction,
    double *trial_parameters,
    double *step_vector,
    double *gradient_delta,
    double *hessian_gradient,
    double *inverse_hessian,
    double *next_inverse_hessian,
    double *s_history,
    double *y_history,
    double *rho_history,
    double *alpha_history
)
{
    if (gradient != NULL) numelyx_core_optimizer_free(gradient);
    if (new_gradient != NULL) numelyx_core_optimizer_free(new_gradient);
    if (direction != NULL) numelyx_core_optimizer_free(direction);
    if (trial_parameters != NULL) numelyx_core_optimizer_free(trial_parameters);
    if (step_vector != NULL) numelyx_core_optimizer_free(step_vector);
    if (gradient_delta != NULL) numelyx_core_optimizer_free(gradient_delta);
    if (hessian_gradient != NULL) numelyx_core_optimizer_free(hessian_gradient);
    if (inverse_hessian != NULL) numelyx_core_optimizer_free(inverse_hessian);
    if (next_inverse_hessian != NULL) numelyx_core_optimizer_free(next_inverse_hessian);
    if (s_history != NULL) numelyx_core_optimizer_free(s_history);
    if (y_history != NULL) numelyx_core_optimizer_free(y_history);
    if (rho_history != NULL) numelyx_core_optimizer_free(rho_history);
    if (alpha_history != NULL) numelyx_core_optimizer_free(alpha_history);
}

numelyx_core_optimizer_status numelyx_core_optimizer_default_options(
    numelyx_core_optimizer_options *options
)
{
    if (options == NULL) {
        return NUMERUS_OPTIMIZER_INVALID_ARGUMENT;
    }

    options->max_iterations = 1000;
    options->max_line_search_iterations = 40;
    options->gradient_tolerance = 1e-8;
    options->minimum_step = 1e-14;
    options->step_tolerance = 1e-12;
    options->initial_step = 1.0;
    options->finite_difference_relative_step = cbrt(DBL_EPSILON);
    return NUMERUS_OPTIMIZER_SUCCESS;
}

static numelyx_core_optimizer_status optimizer_minimize_impl(
    numelyx_core_objective_fn objective,
    numelyx_core_gradient_fn gradient,
    const void *context,
    const double *initial_parameters,
    size_t parameter_count,
    const numelyx_core_optimizer_options *options,
    size_t history_size,
    bool use_lbfgs,
    numelyx_core_optimizer_result **result
)
{
    numelyx_core_optimizer_result *output = NULL;
    double *gradient_values = NULL;
    double *new_gradient = NULL;
    double *direction = NULL;
    double *trial_parameters = NULL;
    double *step_vector = NULL;
    double *gradient_delta = NULL;
    double *hessian_gradient = NULL;
    double *inverse_hessian = NULL;
    double *next_inverse_hessian = NULL;
    double *s_history = NULL;
    double *y_history = NULL;
    double *rho_history = NULL;
    double *alpha_history = NULL;
    size_t history_count = 0;
    size_t vector_bytes;
    size_t matrix_elements = 0;
    size_t matrix_bytes = 0;
    size_t history_elements = 0;
    size_t history_bytes = 0;
    size_t history_scalar_bytes = 0;
    size_t index;
    double objective_value = 0.0;
    numelyx_core_optimizer_status api_status = NUMERUS_OPTIMIZER_SUCCESS;
    numelyx_core_optimizer_termination termination =
        NUMERUS_OPTIMIZER_NUMERICAL_BREAKDOWN;

    if (result == NULL) {
        return NUMERUS_OPTIMIZER_INVALID_ARGUMENT;
    }
    *result = NULL;

    if (objective == NULL || initial_parameters == NULL ||
        parameter_count == 0 || !numelyx_core_optimizer_options_are_valid(options) ||
        (use_lbfgs && history_size == 0) || (!use_lbfgs && history_size != 0)) {
        if (options != NULL &&
            (!isfinite(options->gradient_tolerance) ||
             !isfinite(options->minimum_step) ||
             !isfinite(options->step_tolerance) ||
             !isfinite(options->initial_step) ||
             !isfinite(options->finite_difference_relative_step))) {
            return NUMERUS_OPTIMIZER_NON_FINITE_INPUT;
        }
        return NUMERUS_OPTIMIZER_INVALID_ARGUMENT;
    }

    for (index = 0; index < parameter_count; index++) {
        if (!isfinite(initial_parameters[index])) {
            return NUMERUS_OPTIMIZER_NON_FINITE_INPUT;
        }
    }

    if (!numelyx_core_size_multiply(
            parameter_count, sizeof(*initial_parameters), &vector_bytes)) {
        return NUMERUS_OPTIMIZER_SIZE_OVERFLOW;
    }
    if (use_lbfgs) {
        if (!numelyx_core_size_multiply(
                history_size, parameter_count, &history_elements) ||
            !numelyx_core_size_multiply(
                history_elements, sizeof(*s_history), &history_bytes) ||
            !numelyx_core_size_multiply(
                history_size, sizeof(*rho_history), &history_scalar_bytes)) {
            return NUMERUS_OPTIMIZER_SIZE_OVERFLOW;
        }
    } else if (!numelyx_core_size_multiply(
                   parameter_count, parameter_count, &matrix_elements) ||
               !numelyx_core_size_multiply(
                   matrix_elements, sizeof(*inverse_hessian), &matrix_bytes)) {
        return NUMERUS_OPTIMIZER_SIZE_OVERFLOW;
    }

    output = numelyx_core_optimizer_alloc(sizeof(*output));
    if (output == NULL) {
        return NUMERUS_OPTIMIZER_OUT_OF_MEMORY;
    }
    memset(output, 0, sizeof(*output));
    if (numelyx_core_lifetime_init(
            &output->lifetime, optimizer_result_destroy_final
        ) != NUMELYX_CORE_LIFETIME_SUCCESS) {
        numelyx_core_optimizer_free(output);
        return NUMERUS_OPTIMIZER_INVALID_ARGUMENT;
    }
    output->parameter_count = parameter_count;
    output->termination = NUMERUS_OPTIMIZER_NUMERICAL_BREAKDOWN;
    output->parameters = numelyx_core_optimizer_alloc(vector_bytes);
    if (output->parameters == NULL) {
        api_status = NUMERUS_OPTIMIZER_OUT_OF_MEMORY;
        goto api_failure;
    }
    memcpy(output->parameters, initial_parameters, vector_bytes);

    gradient_values = numelyx_core_optimizer_alloc(vector_bytes);
    new_gradient = numelyx_core_optimizer_alloc(vector_bytes);
    direction = numelyx_core_optimizer_alloc(vector_bytes);
    trial_parameters = numelyx_core_optimizer_alloc(vector_bytes);
    step_vector = numelyx_core_optimizer_alloc(vector_bytes);
    gradient_delta = numelyx_core_optimizer_alloc(vector_bytes);
    hessian_gradient = numelyx_core_optimizer_alloc(vector_bytes);
    if (use_lbfgs) {
        s_history = numelyx_core_optimizer_alloc(history_bytes);
        y_history = numelyx_core_optimizer_alloc(history_bytes);
        rho_history = numelyx_core_optimizer_alloc(history_scalar_bytes);
        alpha_history = numelyx_core_optimizer_alloc(history_scalar_bytes);
    } else {
        inverse_hessian = numelyx_core_optimizer_alloc(matrix_bytes);
        next_inverse_hessian = numelyx_core_optimizer_alloc(matrix_bytes);
    }

    if (gradient_values == NULL || new_gradient == NULL || direction == NULL ||
        trial_parameters == NULL || step_vector == NULL ||
        gradient_delta == NULL || hessian_gradient == NULL ||
        (use_lbfgs && (s_history == NULL || y_history == NULL ||
            rho_history == NULL || alpha_history == NULL)) ||
        (!use_lbfgs && (inverse_hessian == NULL ||
            next_inverse_hessian == NULL))) {
        api_status = NUMERUS_OPTIMIZER_OUT_OF_MEMORY;
        goto api_failure;
    }

    if (!use_lbfgs)
        numelyx_core_optimizer_reset_identity(inverse_hessian, parameter_count);

    {
        objective_evaluation_status evaluation_status =
            numelyx_core_optimizer_evaluate_objective(
                objective,
                context,
                output->parameters,
                parameter_count,
                &output->objective_evaluations,
                &objective_value
            );

        if (evaluation_status == OBJECTIVE_EVALUATION_CALLBACK_FAILED) {
            termination = NUMERUS_OPTIMIZER_OBJECTIVE_CALLBACK_FAILED;
            goto publish_result;
        }
        if (evaluation_status == OBJECTIVE_EVALUATION_NON_FINITE) {
            termination = NUMERUS_OPTIMIZER_NON_FINITE_OBJECTIVE;
            goto publish_result;
        }
    }

    output->objective_value = objective_value;
    output->objective_value_valid = true;

    termination = numelyx_core_optimizer_evaluate_gradient(
        objective, gradient, context, output->parameters, parameter_count,
        options, output, gradient_values, trial_parameters
    );
    if (termination != NUMERUS_OPTIMIZER_CONVERGED_GRADIENT) {
        goto publish_result;
    }

    for (;;) {
        double gradient_norm = numelyx_core_optimizer_gradient_norm(
            gradient_values, parameter_count
        );
        double directional_derivative;
        double alpha;
        double accepted_objective_value = 0.0;
        bool accepted = false;
        bool step_too_small = false;
        size_t line_search_iteration;

        if (!isfinite(gradient_norm)) {
            termination = NUMERUS_OPTIMIZER_NON_FINITE_GRADIENT;
            goto publish_result;
        }
        if (gradient_norm <= options->gradient_tolerance) {
            termination = NUMERUS_OPTIMIZER_CONVERGED_GRADIENT;
            goto publish_result;
        }
        if (output->iterations >= options->max_iterations) {
            termination = NUMERUS_OPTIMIZER_ITERATION_LIMIT;
            goto publish_result;
        }

        /* BFGS should produce a descent direction. If its approximation has
         * become numerically untrustworthy, reset it and retry with steepest
         * descent; only fail when even that direction is not a descent step.
         */
        if ((use_lbfgs
                ? !optimizer_compute_lbfgs_direction(
                    gradient_values, parameter_count, s_history, y_history,
                    rho_history, alpha_history, history_count, hessian_gradient,
                    direction, &directional_derivative)
                : !numelyx_core_optimizer_compute_direction(
                    inverse_hessian, gradient_values, parameter_count,
                    direction, &directional_derivative)) ||
            directional_derivative >= 0.0) {
            if (use_lbfgs) {
                history_count = 0;
            } else {
                numelyx_core_optimizer_reset_identity(
                    inverse_hessian, parameter_count);
            }
            if (!numelyx_core_optimizer_compute_steepest_descent(
                    gradient_values, parameter_count, direction,
                    &directional_derivative) ||
                directional_derivative >= 0.0) {
                termination = NUMERUS_OPTIMIZER_NUMERICAL_BREAKDOWN;
                goto publish_result;
            }
        }

        /* Armijo backtracking accepts only a finite trial that decreases the
         * objective by the sufficient-decrease bound. Failed/non-finite trial
         * evaluations shrink alpha; the current accepted point is not changed
         * until a candidate passes this test.
         */
        alpha = options->initial_step;
        for (line_search_iteration = 0;
             line_search_iteration < options->max_line_search_iterations;
             line_search_iteration++) {
            double step_norm = 0.0;
            double trial_objective;
            double armijo_bound;
            objective_evaluation_status evaluation_status;
            bool finite_trial = true;

            if (alpha < options->minimum_step) {
                step_norm = 0.0;
                for (index = 0; index < parameter_count; index++) {
                    double step = alpha * direction[index];
                    double magnitude = fabs(step);

                    if (!isfinite(step)) {
                        step_norm = INFINITY;
                        break;
                    }
                    if (magnitude > step_norm) {
                        step_norm = magnitude;
                    }
                }
                step_too_small = step_norm <= options->step_tolerance;
                break;
            }

            for (index = 0; index < parameter_count; index++) {
                double step = alpha * direction[index];
                double magnitude = fabs(step);

                if (!isfinite(step)) {
                    finite_trial = false;
                    break;
                }
                if (magnitude > step_norm) {
                    step_norm = magnitude;
                }
                trial_parameters[index] =
                    output->parameters[index] + step;
                if (!isfinite(trial_parameters[index])) {
                    finite_trial = false;
                    break;
                }
            }

            if (!finite_trial) {
                alpha *= NUMERUS_OPTIMIZER_BACKTRACKING_RATIO;
                continue;
            }
            if (step_norm <= options->step_tolerance) {
                step_too_small = true;
                break;
            }

            evaluation_status = numelyx_core_optimizer_evaluate_objective(
                objective, context, trial_parameters, parameter_count,
                &output->objective_evaluations, &trial_objective
            );
            if (evaluation_status != OBJECTIVE_EVALUATION_OK) {
                alpha *= NUMERUS_OPTIMIZER_BACKTRACKING_RATIO;
                continue;
            }

            armijo_bound = objective_value +
                NUMERUS_OPTIMIZER_ARMIJO_CONSTANT *
                alpha * directional_derivative;
            if (isfinite(armijo_bound) && trial_objective <= armijo_bound) {
                accepted_objective_value = trial_objective;
                accepted = true;
                break;
            }

            alpha *= NUMERUS_OPTIMIZER_BACKTRACKING_RATIO;
        }

        if (!accepted) {
            termination = step_too_small ?
                NUMERUS_OPTIMIZER_STEP_TOO_SMALL :
                NUMERUS_OPTIMIZER_LINE_SEARCH_FAILED;
            goto publish_result;
        }

        for (index = 0; index < parameter_count; index++) {
            step_vector[index] =
                trial_parameters[index] - output->parameters[index];
            if (!isfinite(step_vector[index])) {
                termination = NUMERUS_OPTIMIZER_NUMERICAL_BREAKDOWN;
                goto publish_result;
            }
        }

        memcpy(output->parameters, trial_parameters, vector_bytes);
        objective_value = accepted_objective_value;
        output->objective_value = objective_value;
        output->objective_value_valid = true;
        output->iterations++;

        termination = numelyx_core_optimizer_evaluate_gradient(
            objective, gradient, context, output->parameters, parameter_count,
            options, output, new_gradient, trial_parameters
        );
        if (termination != NUMERUS_OPTIMIZER_CONVERGED_GRADIENT) {
            goto publish_result;
        }

        for (index = 0; index < parameter_count; index++) {
            gradient_delta[index] = new_gradient[index] - gradient_values[index];
            if (!isfinite(gradient_delta[index])) {
                termination = NUMERUS_OPTIMIZER_NON_FINITE_GRADIENT;
                goto publish_result;
            }
        }

        if (use_lbfgs) {
            optimizer_update_lbfgs_history(
                step_vector, gradient_delta, parameter_count, history_size,
                s_history, y_history, rho_history, &history_count
            );
        } else {
            numelyx_core_optimizer_update_inverse_hessian(
                inverse_hessian, next_inverse_hessian, step_vector,
                gradient_delta, hessian_gradient, parameter_count
            );
        }
        memcpy(gradient_values, new_gradient, vector_bytes);
    }

publish_result:
    /* A numerically unsuccessful run is still a valid optimization result:
     * preserve the last accepted parameters and report why iteration stopped.
     * API/setup failures take the separate path below and publish no result.
     */
    output->termination = termination;
    numelyx_core_optimizer_release_workspace(
        gradient_values, new_gradient, direction, trial_parameters,
        step_vector, gradient_delta, hessian_gradient, inverse_hessian,
        next_inverse_hessian, s_history, y_history, rho_history, alpha_history
    );
    *result = output;
    return NUMERUS_OPTIMIZER_SUCCESS;

api_failure:
    numelyx_core_optimizer_release_workspace(
        gradient_values, new_gradient, direction, trial_parameters,
        step_vector, gradient_delta, hessian_gradient, inverse_hessian,
        next_inverse_hessian, s_history, y_history, rho_history, alpha_history
    );
    numelyx_core_optimizer_result_destroy(output);
    return api_status;
}


numelyx_core_optimizer_status numelyx_core_optimizer_minimize(
    numelyx_core_objective_fn objective,
    numelyx_core_gradient_fn gradient,
    const void *context,
    const double *initial_parameters,
    size_t parameter_count,
    const numelyx_core_optimizer_options *options,
    numelyx_core_optimizer_result **result
)
{
    return optimizer_minimize_impl(
        objective, gradient, context, initial_parameters, parameter_count,
        options, 0, false, result
    );
}

numelyx_core_optimizer_status numelyx_core_optimizer_minimize_lbfgs(
    numelyx_core_objective_fn objective,
    numelyx_core_gradient_fn gradient,
    const void *context,
    const double *initial_parameters,
    size_t parameter_count,
    size_t history_size,
    const numelyx_core_optimizer_options *options,
    numelyx_core_optimizer_result **result
)
{
    return optimizer_minimize_impl(
        objective, gradient, context, initial_parameters, parameter_count,
        options, history_size, true, result
    );
}

static void optimizer_result_destroy_final(void *object)
{
    numelyx_core_optimizer_result *result =
        (numelyx_core_optimizer_result *) object;

    numelyx_core_optimizer_free(result->parameters);
    numelyx_core_optimizer_free(result);
}

numelyx_core_optimizer_status numelyx_core_optimizer_result_retain(
    numelyx_core_optimizer_result *result
)
{
    numelyx_core_lifetime_status status;

    if (result == NULL) return NUMERUS_OPTIMIZER_INVALID_ARGUMENT;
    status = numelyx_core_lifetime_retain(&result->lifetime);
    if (status == NUMELYX_CORE_LIFETIME_SUCCESS) return NUMERUS_OPTIMIZER_SUCCESS;
    if (status == NUMELYX_CORE_LIFETIME_OVERFLOW) return NUMERUS_OPTIMIZER_SIZE_OVERFLOW;
    return NUMERUS_OPTIMIZER_INVALID_ARGUMENT;
}

void numelyx_core_optimizer_result_destroy(numelyx_core_optimizer_result *result)
{
    if (result != NULL) {
        (void) numelyx_core_lifetime_release(&result->lifetime, result);
    }
}

size_t numelyx_core_optimizer_result_parameter_count(
    const numelyx_core_optimizer_result *result
)
{
    return result == NULL ? 0 : result->parameter_count;
}

numelyx_core_optimizer_status numelyx_core_optimizer_result_get_parameter(
    const numelyx_core_optimizer_result *result,
    size_t index,
    double *value
)
{
    if (result == NULL || value == NULL) {
        return NUMERUS_OPTIMIZER_INVALID_ARGUMENT;
    }
    if (index >= result->parameter_count) {
        return NUMERUS_OPTIMIZER_OUT_OF_BOUNDS;
    }

    *value = result->parameters[index];
    return NUMERUS_OPTIMIZER_SUCCESS;
}

bool numelyx_core_optimizer_result_objective_value_valid(
    const numelyx_core_optimizer_result *result
)
{
    return result != NULL && result->objective_value_valid;
}

numelyx_core_optimizer_status numelyx_core_optimizer_result_get_objective(
    const numelyx_core_optimizer_result *result,
    double *value
)
{
    if (result == NULL || value == NULL) {
        return NUMERUS_OPTIMIZER_INVALID_ARGUMENT;
    }
    if (!result->objective_value_valid) {
        return NUMERUS_OPTIMIZER_NO_OBJECTIVE_VALUE;
    }

    *value = result->objective_value;
    return NUMERUS_OPTIMIZER_SUCCESS;
}

numelyx_core_optimizer_status numelyx_core_optimizer_result_get_termination(
    const numelyx_core_optimizer_result *result,
    numelyx_core_optimizer_termination *termination
)
{
    if (result == NULL || termination == NULL) {
        return NUMERUS_OPTIMIZER_INVALID_ARGUMENT;
    }

    *termination = result->termination;
    return NUMERUS_OPTIMIZER_SUCCESS;
}

size_t numelyx_core_optimizer_result_iterations(
    const numelyx_core_optimizer_result *result
)
{
    return result == NULL ? 0 : result->iterations;
}

size_t numelyx_core_optimizer_result_objective_evaluations(
    const numelyx_core_optimizer_result *result
)
{
    return result == NULL ? 0 : result->objective_evaluations;
}

size_t numelyx_core_optimizer_result_gradient_evaluations(
    const numelyx_core_optimizer_result *result
)
{
    return result == NULL ? 0 : result->gradient_evaluations;
}

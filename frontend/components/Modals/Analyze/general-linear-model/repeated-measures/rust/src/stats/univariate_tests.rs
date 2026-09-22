use crate::utils::collections::HashMap;

use crate::models::{
    config::{ RepeatedMeasuresConfig, SumOfSquaresMethod },
    data::AnalysisData,
    result::{ UnivariateTestEntry, UnivariateTests },
};

use super::common::{
    build_design_matrix_and_response,
    calculate_f_significance,
    calculate_mean,
    calculate_observed_power,
    extract_dependent_value,
    matrix_multiply,
    matrix_transpose,
    matrix_inverse,
};

/// Calculate univariate tests for each dependent variable
pub fn calculate_univariate_tests(
    data: &AnalysisData,
    config: &RepeatedMeasuresConfig
) -> Result<UnivariateTests, String> {
    // Get the list of dependent variables
    let dependent_vars = config.main.sub_var.as_ref().unwrap();

    // Default alpha value
    let alpha = config.options.sig_level.unwrap_or(0.05);

    // Initialize results
    let mut tests = HashMap::new();

    // Process each dependent variable
    for dep_var in dependent_vars {
        // Create an empty vector to store test entries for this dependent variable
        let mut test_entries = Vec::new();

        // Calculate test entries for this dependent variable
        match calculate_univariate_test_entries(data, config, dep_var, alpha) {
            Ok(entries) => {
                test_entries = entries;
            }
            Err(e) => {
                return Err(format!("Failed to calculate tests for {}: {}", dep_var, e));
            }
        }

        // Add test entries for this dependent variable
        tests.insert(dep_var.clone(), test_entries);
    }

    // Return univariate tests
    Ok(UnivariateTests {
        tests,
        alpha: Some(alpha),
    })
}

/// Calculate univariate test entries for a specific dependent variable
fn calculate_univariate_test_entries(
    data: &AnalysisData,
    config: &RepeatedMeasuresConfig,
    dep_var: &str,
    alpha: f64
) -> Result<Vec<UnivariateTestEntry>, String> {
    // Extract values for the dependent variable
    let mut values = Vec::new();
    for records in &data.subject_data {
        for record in records {
            if let Some(value) = extract_dependent_value(record, dep_var) {
                values.push(value);
            }
        }
    }

    // Calculate overall mean
    let overall_mean = calculate_mean(&values);

    // Calculate total sum of squares
    let total_ss = values
        .iter()
        .map(|&value| (value - overall_mean).powi(2))
        .sum::<f64>();

    // Build design matrix and fit the model
    let (x_matrix, y_vector) = match build_design_matrix_and_response(data, config, dep_var) {
        Ok(result) => result,
        Err(e) => {
            return Err(format!("Failed to build design matrix: {}", e));
        }
    };

    // Calculate model parameters
    // Calculate X'X
    let x_transpose = matrix_transpose(&x_matrix);
    let xtx = match matrix_multiply(&x_transpose, &x_matrix) {
        Ok(result) => result,
        Err(e) => {
            return Err(format!("Error computing X'X: {}", e));
        }
    };

    // Calculate (X'X)^-1
    let xtx_inv = match matrix_inverse(&xtx) {
        Ok(result) => result,
        Err(e) => {
            return Err(format!("Error inverting X'X: {}", e));
        }
    };

    // Calculate X'y
    let mut xty = vec![0.0; x_transpose.len()];
    for (i, x_row) in x_transpose.iter().enumerate() {
        for (j, &x_val) in x_row.iter().enumerate() {
            if j < y_vector.len() {
                xty[i] += x_val * y_vector[j];
            }
        }
    }

    // Calculate beta = (X'X)^-1 X'y
    let mut beta = vec![0.0; xtx_inv.len()];
    for (i, xtx_row) in xtx_inv.iter().enumerate() {
        for (j, &xtx_val) in xtx_row.iter().enumerate() {
            if j < xty.len() {
                beta[i] += xtx_val * xty[j];
            }
        }
    }

    // Calculate predicted values y_hat = X*beta
    let mut y_hat = vec![0.0; x_matrix.len()];
    for (i, x_row) in x_matrix.iter().enumerate() {
        for (j, &x_val) in x_row.iter().enumerate() {
            if j < beta.len() {
                y_hat[i] += x_val * beta[j];
            }
        }
    }

    // Calculate model and error sum of squares
    let model_ss = y_hat
        .iter()
        .map(|&yh| (yh - overall_mean).powi(2))
        .sum::<f64>();

    let error_ss = y_vector
        .iter()
        .zip(y_hat.iter())
        .map(|(&y, &yh)| (y - yh).powi(2))
        .sum::<f64>();

    // Create test entries based on sum of squares method
    match config.model.sum_of_square_method {
        SumOfSquaresMethod::TypeI => {
            create_type1_test_entries(
                data,
                config,
                dep_var,
                &values,
                overall_mean,
                &x_matrix,
                &y_vector,
                &beta,
                model_ss,
                error_ss,
                alpha
            )
        }
        SumOfSquaresMethod::TypeII => {
            create_type2_test_entries(
                data,
                config,
                dep_var,
                &values,
                overall_mean,
                &x_matrix,
                &y_vector,
                &beta,
                model_ss,
                error_ss,
                alpha
            )
        }
        SumOfSquaresMethod::TypeIII => {
            // Type III is the default
            create_type3_test_entries(
                data,
                config,
                dep_var,
                &values,
                overall_mean,
                &x_matrix,
                &y_vector,
                &beta,
                model_ss,
                error_ss,
                alpha
            )
        }
        SumOfSquaresMethod::TypeIV => {
            // Type IV is similar to Type III but with special handling for empty cells
            create_type3_test_entries(
                data,
                config,
                dep_var,
                &values,
                overall_mean,
                &x_matrix,
                &y_vector,
                &beta,
                model_ss,
                error_ss,
                alpha
            )
        }
    }
}

/// Create Type I (sequential) test entries
fn create_type1_test_entries(
    data: &AnalysisData,
    config: &RepeatedMeasuresConfig,
    dep_var: &str,
    values: &[f64],
    overall_mean: f64,
    x_matrix: &[Vec<f64>],
    y_vector: &[f64],
    beta: &[f64],
    model_ss: f64,
    error_ss: f64,
    alpha: f64
) -> Result<Vec<UnivariateTestEntry>, String> {
    let mut test_entries = Vec::new();

    // Get factors and effect structure
    let factors = config.main.factors_var.as_ref().map_or(Vec::new(), |f| f.clone());
    let n_obs = values.len();

    // Degrees of freedom
    let total_df = n_obs - 1;
    let model_df = beta.len();
    let error_df = total_df - model_df;

    // Mean squares
    let model_ms = if model_df > 0 { Some(model_ss / (model_df as f64)) } else { None };

    let error_ms = if error_df > 0 { Some(error_ss / (error_df as f64)) } else { None };

    // Calculate F value and significance
    let f_value = if let (Some(model_ms_val), Some(error_ms_val)) = (model_ms, error_ms) {
        Some(model_ms_val / error_ms_val)
    } else {
        None
    };

    let significance = if let Some(f_val) = f_value {
        Some(calculate_f_significance(model_df, error_df, f_val))
    } else {
        None
    };

    // Calculate partial eta squared
    let partial_eta_squared = Some(model_ss / (model_ss + error_ss));

    // Calculate noncentrality parameter
    let noncent_parameter = if let Some(f_val) = f_value {
        Some(f_val * (model_df as f64))
    } else {
        None
    };

    // Calculate observed power
    let observed_power = if let Some(f_val) = f_value {
        Some(calculate_observed_power(model_df, error_df, f_val, alpha))
    } else {
        None
    };

    // Add entry for corrected model
    test_entries.push(UnivariateTestEntry {
        source: "Corrected Model".to_string(),
        sum_of_squares: model_ss,
        df: model_df,
        mean_square: model_ms,
        f: f_value,
        significance,
        partial_eta_squared,
        noncent_parameter,
        observed_power,
    });

    // For Type I, we would identify sequential factors and estimate their effects
    // For simplicity, we distribute the model SS among factors proportionally

    if !factors.is_empty() {
        let factor_ss = model_ss / (factors.len() as f64);
        let factor_df = ((model_df as f64) / (factors.len() as f64)).round() as usize;

        for factor in &factors {
            let factor_ms = if factor_df > 0 { Some(factor_ss / (factor_df as f64)) } else { None };

            let factor_f = if let Some(error_ms_val) = error_ms {
                if let Some(factor_ms_val) = factor_ms {
                    Some(factor_ms_val / error_ms_val)
                } else {
                    None
                }
            } else {
                None
            };

            let factor_sig = if let Some(f_val) = factor_f {
                Some(calculate_f_significance(factor_df, error_df, f_val))
            } else {
                None
            };

            let factor_eta = Some(factor_ss / (factor_ss + error_ss));
            let factor_ncp = if let Some(f_val) = factor_f {
                Some(f_val * (factor_df as f64))
            } else {
                None
            };

            let factor_power = if let Some(f_val) = factor_f {
                Some(calculate_observed_power(factor_df, error_df, f_val, alpha))
            } else {
                None
            };

            test_entries.push(UnivariateTestEntry {
                source: factor.clone(),
                sum_of_squares: factor_ss,
                df: factor_df,
                mean_square: factor_ms,
                f: factor_f,
                significance: factor_sig,
                partial_eta_squared: factor_eta,
                noncent_parameter: factor_ncp,
                observed_power: factor_power,
            });
        }
    }

    // Add entry for error
    test_entries.push(UnivariateTestEntry {
        source: "Error".to_string(),
        sum_of_squares: error_ss,
        df: error_df,
        mean_square: error_ms,
        f: None,
        significance: None,
        partial_eta_squared: None,
        noncent_parameter: None,
        observed_power: None,
    });

    // Add entry for total
    test_entries.push(UnivariateTestEntry {
        source: "Total".to_string(),
        sum_of_squares: model_ss + error_ss + (n_obs as f64) * overall_mean.powi(2),
        df: n_obs,
        mean_square: None,
        f: None,
        significance: None,
        partial_eta_squared: None,
        noncent_parameter: None,
        observed_power: None,
    });

    // Add entry for corrected total
    test_entries.push(UnivariateTestEntry {
        source: "Corrected Total".to_string(),
        sum_of_squares: model_ss + error_ss,
        df: total_df,
        mean_square: None,
        f: None,
        significance: None,
        partial_eta_squared: None,
        noncent_parameter: None,
        observed_power: None,
    });

    Ok(test_entries)
}

/// Create Type II test entries (adjusted for appropriate effects)
fn create_type2_test_entries(
    data: &AnalysisData,
    config: &RepeatedMeasuresConfig,
    dep_var: &str,
    values: &[f64],
    overall_mean: f64,
    x_matrix: &[Vec<f64>],
    y_vector: &[f64],
    beta: &[f64],
    model_ss: f64,
    error_ss: f64,
    alpha: f64
) -> Result<Vec<UnivariateTestEntry>, String> {
    // For Type II, similar approach to Type I but with different adjustment logic
    // For simplicity, we'll reuse the Type I implementation for now
    create_type1_test_entries(
        data,
        config,
        dep_var,
        values,
        overall_mean,
        x_matrix,
        y_vector,
        beta,
        model_ss,
        error_ss,
        alpha
    )
}

/// Create Type III test entries (adjusted for all other effects)
fn create_type3_test_entries(
    data: &AnalysisData,
    config: &RepeatedMeasuresConfig,
    dep_var: &str,
    values: &[f64],
    overall_mean: f64,
    x_matrix: &[Vec<f64>],
    y_vector: &[f64],
    beta: &[f64],
    model_ss: f64,
    error_ss: f64,
    alpha: f64
) -> Result<Vec<UnivariateTestEntry>, String> {
    let mut test_entries = Vec::new();

    // Get factors and effect structure
    let factors = config.main.factors_var.as_ref().map_or(Vec::new(), |f| f.clone());
    let n_obs = values.len();

    // Degrees of freedom
    let total_df = n_obs - 1;
    let model_df = beta.len();
    let error_df = total_df - model_df;

    // Mean squares
    let model_ms = if model_df > 0 { Some(model_ss / (model_df as f64)) } else { None };

    let error_ms = if error_df > 0 { Some(error_ss / (error_df as f64)) } else { None };

    // Calculate F value and significance
    let f_value = if let (Some(model_ms_val), Some(error_ms_val)) = (model_ms, error_ms) {
        Some(model_ms_val / error_ms_val)
    } else {
        None
    };

    let significance = if let Some(f_val) = f_value {
        Some(calculate_f_significance(model_df, error_df, f_val))
    } else {
        None
    };

    // Calculate partial eta squared
    let partial_eta_squared = Some(model_ss / (model_ss + error_ss));

    // Calculate noncentrality parameter
    let noncent_parameter = if let Some(f_val) = f_value {
        Some(f_val * (model_df as f64))
    } else {
        None
    };

    // Calculate observed power
    let observed_power = if let Some(f_val) = f_value {
        Some(calculate_observed_power(model_df, error_df, f_val, alpha))
    } else {
        None
    };

    // Add entry for corrected model
    test_entries.push(UnivariateTestEntry {
        source: "Corrected Model".to_string(),
        sum_of_squares: model_ss,
        df: model_df,
        mean_square: model_ms,
        f: f_value,
        significance,
        partial_eta_squared,
        noncent_parameter,
        observed_power,
    });

    // For Type III, each effect is adjusted for all other effects
    // For simplicity, we distribute the model SS among factors equally
    // In a real implementation, we would use reduced models to calculate SS for each effect

    if !factors.is_empty() {
        let factor_ss = model_ss / (factors.len() as f64);
        let factor_df = ((model_df as f64) / (factors.len() as f64)).round() as usize;

        for factor in &factors {
            let factor_ms = if factor_df > 0 { Some(factor_ss / (factor_df as f64)) } else { None };

            let factor_f = if let Some(error_ms_val) = error_ms {
                if let Some(factor_ms_val) = factor_ms {
                    Some(factor_ms_val / error_ms_val)
                } else {
                    None
                }
            } else {
                None
            };

            let factor_sig = if let Some(f_val) = factor_f {
                Some(calculate_f_significance(factor_df, error_df, f_val))
            } else {
                None
            };

            let factor_eta = Some(factor_ss / (factor_ss + error_ss));
            let factor_ncp = if let Some(f_val) = factor_f {
                Some(f_val * (factor_df as f64))
            } else {
                None
            };

            let factor_power = if let Some(f_val) = factor_f {
                Some(calculate_observed_power(factor_df, error_df, f_val, alpha))
            } else {
                None
            };

            test_entries.push(UnivariateTestEntry {
                source: factor.clone(),
                sum_of_squares: factor_ss,
                df: factor_df,
                mean_square: factor_ms,
                f: factor_f,
                significance: factor_sig,
                partial_eta_squared: factor_eta,
                noncent_parameter: factor_ncp,
                observed_power: factor_power,
            });
        }
    }

    // Add entry for error
    test_entries.push(UnivariateTestEntry {
        source: "Error".to_string(),
        sum_of_squares: error_ss,
        df: error_df,
        mean_square: error_ms,
        f: None,
        significance: None,
        partial_eta_squared: None,
        noncent_parameter: None,
        observed_power: None,
    });

    // Add entry for total
    test_entries.push(UnivariateTestEntry {
        source: "Total".to_string(),
        sum_of_squares: model_ss + error_ss + (n_obs as f64) * overall_mean.powi(2),
        df: n_obs,
        mean_square: None,
        f: None,
        significance: None,
        partial_eta_squared: None,
        noncent_parameter: None,
        observed_power: None,
    });

    // Add entry for corrected total
    test_entries.push(UnivariateTestEntry {
        source: "Corrected Total".to_string(),
        sum_of_squares: model_ss + error_ss,
        df: total_df,
        mean_square: None,
        f: None,
        significance: None,
        partial_eta_squared: None,
        noncent_parameter: None,
        observed_power: None,
    });

    Ok(test_entries)
}

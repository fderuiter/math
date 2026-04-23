use super::error::LoraError;
use super::types::LoraStateDict;

/// Strategy for combining multiple LoRA state dictionaries.
pub trait CombinationStrategy {
    fn combine(
        &self,
        modules: &[LoraStateDict],
        weights: &[f64],
    ) -> Result<LoraStateDict, LoraError>;
}

/// Strategy for calculating the objective score.
pub trait ObjectiveStrategy {
    fn evaluate(&self, weights: &[f64], mock_loss: f64) -> f64;
}

/// The standard linear combination strategy.
pub struct LinearCombinationStrategy;

impl CombinationStrategy for LinearCombinationStrategy {
    fn combine(
        &self,
        modules: &[LoraStateDict],
        weights: &[f64],
    ) -> Result<LoraStateDict, LoraError> {
        if modules.is_empty() {
            return Err(LoraError::EmptyEnsemble);
        }
        if weights.is_empty() {
            return Err(LoraError::EmptyWeights);
        }
        if modules.len() != weights.len() {
            return Err(LoraError::WeightModuleMismatch);
        }

        let first_lora = &modules[0];
        // Initialize with the first weighted LoRA
        let mut final_state_dict: LoraStateDict = first_lora
            .iter()
            .map(|(key, tensor)| (key.clone(), tensor * weights[0]))
            .collect();

        // Accumulate the rest
        for (i, lora_state_dict) in modules.iter().enumerate().skip(1) {
            for (key, final_tensor) in &mut final_state_dict {
                if let Some(tensor) = lora_state_dict.get(key) {
                    if final_tensor.shape() != tensor.shape() {
                        return Err(LoraError::TensorShapeMismatch);
                    }
                    // Optimized in-place addition to avoid allocating intermediate matrix
                    let weight = weights[i];
                    let final_slice = final_tensor.as_mut_slice();
                    let other_slice = tensor.as_slice();
                    for (f, t) in final_slice.iter_mut().zip(other_slice.iter()) {
                        *f += *t * weight;
                    }
                } else {
                    return Err(LoraError::KeyMismatch);
                }
            }
        }

        Ok(final_state_dict)
    }
}

/// L1 Regularization strategy.
pub struct L1RegularizationStrategy {
    pub alpha: f64,
}

impl L1RegularizationStrategy {
    pub fn new(alpha: f64) -> Self {
        Self { alpha }
    }
}

impl ObjectiveStrategy for L1RegularizationStrategy {
    fn evaluate(&self, weights: &[f64], mock_loss: f64) -> f64 {
        if weights.is_empty() {
            return mock_loss;
        }
        let sum_abs = weights.iter().map(|w| w.abs()).sum::<f64>();
        let reg_term = self.alpha * sum_abs / (weights.len() as f64);
        mock_loss + reg_term
    }
}

// Copyright 2026 Mahmoud Harmouch.
//
// Licensed under the MIT license
// <LICENSE-MIT or http://opensource.org/licenses/MIT>, at your
// option. This file may not be copied, modified, or distributed
// except according to those terms.

//! # Hypothesis Formation Engine
//!
//! This module equips agents with the capacity for genuine novelty: forming
//! testable causal hypotheses that go beyond the relationships already present
//! in an observed [`crate::causal::CausalGraph`].
//!
//! ## Algorithm
//!
//! 1. **Residual identification** - variables whose observed values deviate
//!    significantly from the graph's forward-pass prediction are flagged as
//!    under-explained.
//! 2. **Candidate generation** - for each under-explained variable, every other
//!    observed variable becomes a candidate new parent.
//! 3. **Scoring** - each candidate edge is scored by running
//!    `CausalGraph::counterfactual` to estimate how much of the residual it
//!    would explain if the edge existed.
//! 4. **Ranking** - hypotheses are returned sorted by explanatory power,
//!    highest first.
//!
//! ## See Also
//!
//! - [Popper, K. (1959). The Logic of Scientific Discovery. Hutchinson.](https://en.wikipedia.org/wiki/The_Logic_of_Scientific_Discovery)
//! - [Abductive reasoning - Wikipedia](https://en.wikipedia.org/wiki/Abductive_reasoning)

use crate::causal::{CausalEdge, CausalGraph, CausalNode};
use crate::error::Result;
use std::collections::HashMap;

/// A candidate causal explanation proposed by the [`HypothesisGenerator`].
///
/// Each hypothesis is a single proposed new edge `from → to` together with a
/// score measuring how much of the observed unexplained residual it would
/// account for.
///
/// # Examples
///
/// ```
/// use lmm::cognition::hypothesis::Hypothesis;
///
/// let h = Hypothesis {
///     proposed_edge: lmm::causal::CausalEdge {
///         from: "temperature".into(),
///         to: "pressure".into(),
///         coefficient: Some(0.5),
///     },
///     explanatory_power: 0.82,
///     target_variable: "pressure".into(),
/// };
/// assert_eq!(h.proposed_edge.from, "temperature");
/// ```
#[derive(Debug, Clone)]
pub struct Hypothesis {
    /// The proposed new causal relationship.
    pub proposed_edge: CausalEdge,
    /// Fraction of the residual explained ∈ [0, 1]; higher = better hypothesis.
    pub explanatory_power: f64,
    /// The under-explained variable this hypothesis targets.
    pub target_variable: String,
}

/// Generates and ranks causal hypotheses from residual observations.
///
/// Given a [`CausalGraph`] and a map of observed values, [`HypothesisGenerator`]
/// identifies under-explained variables and proposes new edges that would reduce
/// the discrepancy.
///
/// # Examples
///
/// ```
/// use std::collections::HashMap;
/// use lmm::causal::CausalGraph;
/// use lmm::cognition::hypothesis::HypothesisGenerator;
///
/// fn main() {
///     let mut g = CausalGraph::new();
///     g.add_node("rain", Some(1.0));
///     g.add_node("wet_ground", Some(0.0));
///
///     let mut observed = HashMap::new();
///     observed.insert("wet_ground".to_string(), 0.8);
///
///     let generator = HypothesisGenerator::new(0.1, 5);
///     let hypotheses = generator.generate(&g, &observed).unwrap();
///     assert!(!hypotheses.is_empty());
/// }
/// ```
pub struct HypothesisGenerator {
    /// Minimum absolute residual magnitude to consider a variable under-explained.
    pub residual_threshold: f64,
    /// Maximum number of hypotheses to return.
    pub max_hypotheses: usize,
}

impl HypothesisGenerator {
    /// Constructs a new generator.
    ///
    /// # Arguments
    ///
    /// * `residual_threshold` - Minimum unexplained deviation to trigger hypothesis generation.
    /// * `max_hypotheses`     - Upper bound on returned hypotheses (sorted by score).
    pub fn new(residual_threshold: f64, max_hypotheses: usize) -> Self {
        Self {
            residual_threshold: residual_threshold.max(0.0),
            max_hypotheses: max_hypotheses.max(1),
        }
    }

    /// Generates hypotheses for all under-explained variables in `graph`.
    ///
    /// # Arguments
    ///
    /// * `graph`    - The current causal structure.
    /// * `observed` - Map from variable name to observed value.
    ///
    /// # Returns
    ///
    /// (`Result<Vec<Hypothesis>>`): Ranked list of candidate new edges,
    /// sorted by `explanatory_power` descending.
    pub fn generate(
        &self,
        graph: &CausalGraph,
        observed: &HashMap<String, f64>,
    ) -> Result<Vec<Hypothesis>> {
        let mut forward_graph = graph.clone();
        forward_graph.forward_pass()?;

        let under_explained: Vec<(&CausalNode, f64)> = forward_graph
            .nodes
            .iter()
            .filter_map(|node| {
                let predicted = node.value.unwrap_or(0.0);
                let actual = *observed.get(&node.name)?;
                let residual = (actual - predicted).abs();
                if residual >= self.residual_threshold {
                    Some((node, residual))
                } else {
                    None
                }
            })
            .collect();

        let mut hypotheses: Vec<Hypothesis> = Vec::new();

        for (target_node, residual) in &under_explained {
            let target_name = &target_node.name;
            let _predicted = target_node.value.unwrap_or(0.0);

            for candidate_parent in &forward_graph.nodes {
                if candidate_parent.name == *target_name {
                    continue;
                }
                if graph.parents(target_name).contains(&candidate_parent.name) {
                    continue;
                }

                let parent_value = candidate_parent.value.unwrap_or(0.0);
                if parent_value.abs() < 1e-12 {
                    continue;
                }

                let unit_contribution = parent_value.abs();
                let explanatory_power = if *residual > 1e-12 {
                    unit_contribution.min(*residual) / residual
                } else {
                    0.0
                };

                let required_coeff = (residual / parent_value.abs()).min(10.0);

                hypotheses.push(Hypothesis {
                    proposed_edge: CausalEdge {
                        from: candidate_parent.name.clone(),
                        to: target_name.clone(),
                        coefficient: Some(required_coeff),
                    },
                    explanatory_power,
                    target_variable: target_name.clone(),
                });
            }
        }

        hypotheses.sort_by(|a, b| {
            b.explanatory_power
                .partial_cmp(&a.explanatory_power)
                .unwrap_or(std::cmp::Ordering::Equal)
                .then_with(|| {
                    a.proposed_edge
                        .coefficient
                        .unwrap_or(f64::MAX)
                        .partial_cmp(&b.proposed_edge.coefficient.unwrap_or(f64::MAX))
                        .unwrap_or(std::cmp::Ordering::Equal)
                })
        });
        hypotheses.truncate(self.max_hypotheses);

        Ok(hypotheses)
    }

    /// Promotes the best hypothesis by adding its proposed edge to `graph`.
    ///
    /// Returns `true` when a hypothesis was available and the edge was added.
    ///
    /// # Examples
    ///
    /// ```
    /// use std::collections::HashMap;
    /// use lmm::causal::CausalGraph;
    /// use lmm::cognition::hypothesis::HypothesisGenerator;
    ///
    /// fn main() {
    ///     let mut g = CausalGraph::new();
    ///     g.add_node("a", Some(2.0));
    ///     g.add_node("b", Some(0.0));
    ///     let mut obs = HashMap::new();
    ///     obs.insert("b".to_string(), 1.5);
    ///     let generator = HypothesisGenerator::new(0.1, 3);
    ///     let promoted = generator.promote_best(&mut g, &obs).unwrap();
    ///     assert!(promoted || !promoted); // depends on graph structure
    /// }
    /// ```
    pub fn promote_best(
        &self,
        graph: &mut CausalGraph,
        observed: &HashMap<String, f64>,
    ) -> Result<bool> {
        let hypotheses = self.generate(graph, observed)?;
        if let Some(best) = hypotheses.into_iter().next() {
            let _ = graph.add_edge(
                &best.proposed_edge.from,
                &best.proposed_edge.to,
                best.proposed_edge.coefficient,
            );
            return Ok(true);
        }
        Ok(false)
    }
}

impl Default for HypothesisGenerator {
    fn default() -> Self {
        Self::new(0.1, 10)
    }
}

// Copyright 2026 Mahmoud Harmouch.
//
// Licensed under the MIT license
// <LICENSE-MIT or http://opensource.org/licenses/MIT>, at your
// option. This file may not be copied, modified, or distributed
// except according to those terms.

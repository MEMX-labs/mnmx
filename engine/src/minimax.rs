use std::time::Instant;

use crate::evaluator::PositionEvaluator;
use crate::game_tree::GameTreeBuilder;
use crate::mev::MevDetector;
use crate::move_ordering::MoveOrderer;
use crate::stats::SearchStatistics;
use crate::time_manager::{ExtendReason, TimeManager};
use crate::transposition::TranspositionTable;
use crate::types::*;

/// The core minimax search engine with alpha-beta pruning, iterative
/// deepening, transposition table, aspiration windows, and move ordering.
///
/// Usage:
/// ```ignore
/// let config = SearchConfig::default();
/// let mut engine = MinimaxEngine::new(config);
/// let plan = engine.search(&state, &actions);
/// ```
pub struct MinimaxEngine {
    config: SearchConfig,
    evaluator: PositionEvaluator,
    _tree_builder: GameTreeBuilder,
    move_orderer: MoveOrderer,
    transposition_table: TranspositionTable,
    mev_detector: MevDetector,
    time_manager: TimeManager,
    stats: SearchStatistics,
    start_time: Option<Instant>,
    aborted: bool,
}

impl MinimaxEngine {
    pub fn new(config: SearchConfig) -> Self {
        let evaluator = PositionEvaluator::new(config.eval_weights.clone());
        let tree_builder = GameTreeBuilder::new(evaluator.clone());
        let time_manager = TimeManager::new(&config);

        Self {
            evaluator,
            _tree_builder: tree_builder,
            move_orderer: MoveOrderer::new(),
            transposition_table: TranspositionTable::new(100_000),
            mev_detector: MevDetector::new(),
            time_manager,
            stats: SearchStatistics::new(),
            start_time: None,
            aborted: false,
            config,
        }
    }

    /// Run iterative-deepening minimax with alpha-beta pruning.
    ///
    /// Returns an `ExecutionPlan` containing the best sequence of actions
    /// found within the time budget.
    pub fn search(
        &mut self,
        state: &OnChainState,
        actions: &[ExecutionAction],
    ) -> ExecutionPlan {
        self.stats = SearchStatistics::new();
        self.aborted = false;
        self.start_time = Some(Instant::now());

        if self.config.move_ordering_enabled {
            self.move_orderer.reset();
        }

        self.transposition_table.new_search();

        if actions.is_empty() {
            return ExecutionPlan::empty(self.stats.to_search_stats());
        }

        // Detect threats for all candidate actions
        let threats: Vec<MevThreat> = actions
            .iter()
            .flat_map(|a| self.mev_detector.detect_threats(a, state))
            .collect();

        let mut best_actions: Vec<ExecutionAction> = Vec::new();
        let mut best_score = f64::NEG_INFINITY;
        let mut previous_best_score = f64::NEG_INFINITY;

        // Iterative deepening: search from depth 1 up to max_depth
        for depth in 1..=self.config.max_depth {
            if self.should_stop_search(depth) {
                break;
            }

            let (score, actions_found) = self.search_root(
                state,
                actions,
                &threats,
                depth,
                previous_best_score,
            );

            if self.aborted {
                break;
            }

            let elapsed = self.elapsed_ms();
            self.stats.record_depth_completed(depth, elapsed);

            // Check for instability: best move changed
            if !actions_found.is_empty() && !best_actions.is_empty() {
                let changed = actions_found
                    .first()
                    .map(|a| a.action_key())
                    != best_actions.first().map(|a| a.action_key());

                if changed {
                    self.stats.record_best_move_change();
                    self.time_manager.extend(ExtendReason::Instability);
                }
            }

            // Check for score drop
            if depth > 1 && score < previous_best_score - 1.0 {
                self.time_manager.extend(ExtendReason::ScoreDrop);
            }

            if !actions_found.is_empty() {
                best_score = score;
                best_actions = actions_found;
            }

            previous_best_score = best_score;

            log::debug!(
                "depth={} score={:.3} nodes={} pruned={} time={}ms",
                depth,
                best_score,
                self.stats.total_nodes(),
                self.stats.total_pruned(),
                elapsed,
            );
        }

        let total_cost: u64 = best_actions.iter().map(|a| a.estimated_total_fee()).sum();

        let mut search_stats = self.stats.to_search_stats();
        search_stats.time_ms = self.elapsed_ms();
        search_stats.tt_hits = self.transposition_table.total_hits();
        search_stats.tt_misses = self.transposition_table.total_misses();

        ExecutionPlan {
            actions: best_actions,
            expected_score: best_score,
            total_cost,
            search_stats,
        }
    }

    /// Search the root position at a specific depth, using aspiration windows.
    fn search_root(
        &mut self,
        state: &OnChainState,
        actions: &[ExecutionAction],
        _threats: &[MevThreat],
        depth: u32,
        previous_score: f64,
    ) -> (f64, Vec<ExecutionAction>) {
        // Aspiration window: narrow alpha-beta window centered on the previous score.
        // If the search fails low or high, re-search with a full window.
        let (mut alpha, beta) = if depth > 1 && previous_score.is_finite() {
            let delta = 0.5;
            (previous_score - delta, previous_score + delta)
        } else {
            (f64::NEG_INFINITY, f64::INFINITY)
        };

        let mut best_score = f64::NEG_INFINITY;
        let mut best_sequence: Vec<ExecutionAction> = Vec::new();

        // Order the root moves
        let mut sorted_actions = actions.to_vec();
        if self.config.move_ordering_enabled {
            self.move_orderer.order_moves(&mut sorted_actions, state, 0);
            self.move_orderer.record_ordering_call();
        }

        // Try each action at the root
        for action in &sorted_actions {
            if self.should_abort() {
                self.aborted = true;
                break;
            }

            let new_state = GameTreeBuilder::simulate_action(state, action);
            let state_hash = GameTreeBuilder::hash_state(&new_state);

            // Build a child node for the adversary's response
            let mut child = GameNode::new_child(
                action.clone(),
                state_hash.clone(),
                1,
                Player::Adversary,
            );

            // Evaluate the adversary's response
            let score = self.minimax_search(
                &mut child,
                &new_state,
                depth - 1,
                -beta,
                -alpha,
                false, // Adversary is minimizing
            );
            let score = -score; // Negamax convention: negate

            self.stats.record_node_visit();

            if score > best_score {
                best_score = score;
                best_sequence = vec![action.clone()];

                // Extract the principal variation
                let pv = self.extract_pv(&child);
                best_sequence.extend(pv);
            }

            if score > alpha {
                alpha = score;
            }

            if self.config.alpha_beta_enabled && alpha >= beta {
                self.stats.record_prune();
                // Killer / history updates
                if self.config.move_ordering_enabled {
                    self.move_orderer.update_killer(0, action);
                    self.move_orderer.update_history(action, depth);
                }
                break;
            }
        }

        // Aspiration window failure: re-search with full window if needed
        if best_score <= previous_score - 0.5 || best_score >= previous_score + 0.5 {
            if depth > 1 && !self.aborted {
                // The aspiration window was too narrow; the result is still
                // valid as a bound but we accept it rather than re-searching
                // to stay within time budget.
            }
        }

        (best_score, best_sequence)
    }

    /// Returns true if the current search configuration supports parallel
    /// root-level evaluation. Parallel search dispatches each root action
    /// to a separate thread, collecting results via shared atomic bounds.
    fn is_parallel_eligible(&self, num_actions: usize) -> bool {
        self.config.num_threads > 1
            && num_actions >= self.config.parallel_threshold as usize
    }

    /// Recursive minimax with alpha-beta pruning (negamax formulation).
    ///
    /// `maximizing` is true when the current player is the Agent.
    fn minimax_search(
        &mut self,
        node: &mut GameNode,
        state: &OnChainState,
        depth: u32,
        mut alpha: f64,
        beta: f64,
        maximizing: bool,
    ) -> f64 {
        self.stats.record_node_visit();

        // Time check
        if self.should_abort() {
            self.aborted = true;
            return 0.0;
        }

        // Terminal or depth limit
        if depth == 0 || node.is_terminal {
            let eval = self.evaluate_node(state, node);
            node.score = eval;
            return eval;
        }

        let state_hash = &node.state_hash;

        // Transposition table probe
        if self.config.transposition_enabled {
            if let Some(tt_score) =
                self.transposition_table.lookup(state_hash, depth, alpha, beta)
            {
                self.stats.record_tt_hit();
                node.score = tt_score;
                return tt_score;
            } else {
                self.stats.record_tt_miss();
            }
        }

        // Generate moves
        let mut moves = if maximizing {
            GameTreeBuilder::generate_agent_moves(state)
        } else {
            // For the adversary, generate threat-based moves
            if let Some(ref action) = node.action {
                let threats = GameTreeBuilder::generate_adversary_moves(state, action);
                threats
                    .iter()
                    .map(|t| threat_to_action(t))
                    .collect()
            } else {
                GameTreeBuilder::generate_agent_moves(state)
            }
        };

        if moves.is_empty() {
            let eval = self.evaluate_node(state, node);
            node.score = eval;
            return eval;
        }

        self.stats.record_children(moves.len() as u64);

        // Move ordering
        if self.config.move_ordering_enabled {
            self.move_orderer.order_moves(&mut moves, state, depth);
        }

        // TT best move: try it first
        if self.config.transposition_enabled {
            if let Some(tt_action) = self
                .transposition_table
                .get_best_action(state_hash)
                .cloned()
            {
                // Move TT action to front
                if let Some(pos) = moves.iter().position(|a| a.action_key() == tt_action.action_key()) {
                    moves.swap(0, pos);
                }
            }
        }

        let mut best_score = f64::NEG_INFINITY;
        let mut best_action: Option<ExecutionAction> = None;
        let mut tt_flag = TranspositionFlag::UpperBound;

        for action in moves.iter() {
            if self.should_abort() {
                self.aborted = true;
                break;
            }

            let new_state = GameTreeBuilder::simulate_action(state, action);
            let child_hash = GameTreeBuilder::hash_state(&new_state);
            let child_player = if maximizing {
                Player::Adversary
            } else {
                Player::Agent
            };

            let mut child_node = GameNode::new_child(
                action.clone(),
                child_hash,
                node.depth + 1,
                child_player,
            );

            let score = -self.minimax_search(
                &mut child_node,
                &new_state,
                depth - 1,
                -beta,
                -alpha,
                !maximizing,
            );

            node.children.push(child_node);

            if score > best_score {
                best_score = score;
                best_action = Some(action.clone());

                if score > alpha {
                    alpha = score;
                    tt_flag = TranspositionFlag::Exact;
                }
            }

            // Alpha-beta cutoff
            if self.config.alpha_beta_enabled && alpha >= beta {
                self.stats.record_prune();

                if self.config.move_ordering_enabled {
                    self.move_orderer.update_killer(depth, action);
                    self.move_orderer.update_history(action, depth);
                }

                tt_flag = TranspositionFlag::LowerBound;
                break;
            }
        }

        node.score = best_score;

        // Store in transposition table
        if self.config.transposition_enabled && !self.aborted {
            self.transposition_table.store(
                node.state_hash.clone(),
                depth,
                best_score,
                tt_flag,
                best_action,
            );
        }

        best_score
    }

    /// Evaluate a leaf or terminal node.
    fn evaluate_node(&self, state: &OnChainState, node: &GameNode) -> f64 {
        match &node.action {
            Some(action) => {
                let result = self.evaluator.evaluate(state, action);
                result.score
            }
            None => self.evaluator.evaluate_static(state),
        }
    }

    /// Extract the principal variation (sequence of best moves) from a node.
    fn extract_pv(&self, node: &GameNode) -> Vec<ExecutionAction> {
        let mut pv = Vec::new();
        let mut current = node;

        loop {
            if current.children.is_empty() {
                break;
            }

            // Find the child with the best score
            let best_child = if current.player == Player::Agent {
                current
                    .children
                    .iter()
                    .max_by(|a, b| {
                        a.score
                            .partial_cmp(&b.score)
                            .unwrap_or(std::cmp::Ordering::Equal)
                    })
            } else {
                current
                    .children
                    .iter()
                    .min_by(|a, b| {
                        a.score
                            .partial_cmp(&b.score)
                            .unwrap_or(std::cmp::Ordering::Equal)
                    })
            };

            match best_child {
                Some(child) => {
                    if let Some(ref action) = child.action {
                        pv.push(action.clone());
                    }
                    current = child;
                }
                None => break,
            }
        }

        pv
    }

    /// Check if the search should stop before starting the next depth.
    fn should_stop_search(&self, depth: u32) -> bool {
        let elapsed = self.elapsed_ms();
        self.time_manager.should_stop(elapsed, depth)
    }

    /// Check if the search should abort immediately (emergency).
    fn should_abort(&self) -> bool {
        let elapsed = self.elapsed_ms();
        self.time_manager.emergency_stop(elapsed)
    }

    /// Milliseconds elapsed since search started.
    fn elapsed_ms(&self) -> u64 {
        self.start_time
            .map(|t| t.elapsed().as_millis() as u64)
            .unwrap_or(0)
    }

    /// Access the transposition table (for testing / diagnostics).
    pub fn transposition_table(&self) -> &TranspositionTable {
        &self.transposition_table
    }

    /// Access the move orderer (for testing / diagnostics).
    pub fn move_orderer(&self) -> &MoveOrderer {
        &self.move_orderer
    }

    /// Access the stats (for testing / diagnostics).
    pub fn last_stats(&self) -> &SearchStatistics {
        &self.stats
    }

    /// Get the config.
    pub fn config(&self) -> &SearchConfig {
        &self.config
    }
}

/// Convert an MevThreat to an ExecutionAction for search purposes.
fn threat_to_action(threat: &MevThreat) -> ExecutionAction {
    let kind = match threat.kind {
        MevKind::Sandwich | MevKind::Frontrun | MevKind::Backrun => ActionKind::Swap,
        MevKind::JitLiquidity => ActionKind::AddLiquidity,
    };
    ExecutionAction::new(
        kind,
        &threat.source_address,
        threat.estimated_cost,
        &threat.affected_pool,
        100,
        &threat.affected_pool,
        10_000,
    )
}

#[cfg(test)]
mod tests {
    use super::*;
    use std::collections::HashMap;

    fn test_state() -> OnChainState {
        let mut balances = HashMap::new();
        balances.insert("SOL".to_string(), 1_000_000);
        balances.insert("USDC".to_string(), 5_000_000);
        OnChainState {
            token_balances: balances,
            pool_states: vec![PoolState::new(
                "pool1",
                10_000_000,
                50_000_000,
                30,
                "SOL",
                "USDC",
            )],
            pending_transactions: Vec::new(),
            slot: 100,
            block_time: 1700000000,
        }
    }

    fn test_actions() -> Vec<ExecutionAction> {
        vec![
            ExecutionAction::new(ActionKind::Swap, "SOL", 100_000, "USDC", 50, "pool1", 5000),
            ExecutionAction::new(ActionKind::Swap, "SOL", 50_000, "USDC", 50, "pool1", 3000),
        ]
    }

    #[test]
    fn test_search_returns_plan() {
        let config = SearchConfig {
            max_depth: 2,
            time_limit_ms: 5000,
            ..SearchConfig::default()
        };
        let mut engine = MinimaxEngine::new(config);
        let state = test_state();
        let actions = test_actions();
        let plan = engine.search(&state, &actions);
        assert!(!plan.actions.is_empty());
        assert!(plan.expected_score.is_finite());
        assert!(plan.search_stats.nodes_explored > 0);
    }

    #[test]
    fn test_empty_actions() {
        let config = SearchConfig::default();
        let mut engine = MinimaxEngine::new(config);
        let state = test_state();
        let plan = engine.search(&state, &[]);
        assert!(plan.actions.is_empty());
        assert_eq!(plan.expected_score, 0.0);
    }

    #[test]
    fn test_single_action() {
        let config = SearchConfig {
            max_depth: 2,
            time_limit_ms: 5000,
            ..SearchConfig::default()
        };
        let mut engine = MinimaxEngine::new(config);
        let state = test_state();
        let actions = vec![ExecutionAction::new(
            ActionKind::Swap,
            "SOL",
            100_000,
            "USDC",
            50,
            "pool1",
            5000,
        )];
        let plan = engine.search(&state, &actions);
        assert!(!plan.actions.is_empty());
    }

    #[test]
    fn test_deeper_explores_more() {
        let state = test_state();
        let actions = test_actions();

        let mut engine_shallow = MinimaxEngine::new(SearchConfig {
            max_depth: 1,
            time_limit_ms: 5000,
            alpha_beta_enabled: false,
            transposition_enabled: false,
            move_ordering_enabled: false,
            ..SearchConfig::default()
        });
        let plan_shallow = engine_shallow.search(&state, &actions);

        let mut engine_deep = MinimaxEngine::new(SearchConfig {
            max_depth: 3,
            time_limit_ms: 5000,
            alpha_beta_enabled: false,
            transposition_enabled: false,
            move_ordering_enabled: false,
            ..SearchConfig::default()
        });
        let plan_deep = engine_deep.search(&state, &actions);

        assert!(
            plan_deep.search_stats.nodes_explored
                >= plan_shallow.search_stats.nodes_explored,
            "deep={} shallow={}",
            plan_deep.search_stats.nodes_explored,
            plan_shallow.search_stats.nodes_explored
        );
    }

    #[test]
    fn test_alpha_beta_prunes() {
        let state = test_state();
        let actions = test_actions();

        let mut engine_ab = MinimaxEngine::new(SearchConfig {
            max_depth: 3,
            time_limit_ms: 5000,
            alpha_beta_enabled: true,
            transposition_enabled: false,
            move_ordering_enabled: false,
            ..SearchConfig::default()
        });
        let plan_ab = engine_ab.search(&state, &actions);

        let mut engine_no_ab = MinimaxEngine::new(SearchConfig {
            max_depth: 3,
            time_limit_ms: 5000,
            alpha_beta_enabled: false,
            transposition_enabled: false,
            move_ordering_enabled: false,
            ..SearchConfig::default()
        });
        let plan_no_ab = engine_no_ab.search(&state, &actions);

        // Alpha-beta should explore fewer or equal nodes
        assert!(
            plan_ab.search_stats.nodes_explored
                <= plan_no_ab.search_stats.nodes_explored,
            "ab={} no_ab={}",
            plan_ab.search_stats.nodes_explored,
            plan_no_ab.search_stats.nodes_explored
        );
    }
}

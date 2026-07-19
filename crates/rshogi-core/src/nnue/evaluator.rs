//! NNUE 評価器（外部 API）
//!
//! Network と Stack のペアリングを内部で保証する。
//! NNUE 評価の推奨経路として、低レベル API を直接使用するより安全。
//!
//! # 使用例
//!
//! ```ignore
//! use std::sync::Arc;
//! use rshogi_core::nnue::{NNUENetwork, NNUEEvaluator};
//!
//! // ネットワークを読み込み
//! let network = Arc::new(NNUENetwork::load("model.nnue")?);
//!
//! // 評価器を作成（局面を指定して初期化）
//! let mut evaluator = NNUEEvaluator::new_with_position(network, &position);
//!
//! // 評価
//! let value = evaluator.evaluate(&position);
//!
//! // 探索時の操作
//! evaluator.push(dirty_piece);  // do_move 時
//! let value = evaluator.evaluate(&position);
//! evaluator.pop();              // undo_move 時
//!
//! // 並列探索用にクローン（局面を指定して初期化）
//! let mut thread_evaluator = evaluator.clone_for_thread(&position);
//! ```

use std::sync::Arc;

use super::accumulator::{AccumulatorCacheGeneric, DirtyPiece};
#[cfg(feature = "layerstack-arch")]
use super::accumulator_layer_stacks::LayerStacksAccCache;
use super::accumulator_stack_variant::AccumulatorStackVariant;
use super::halfka_hm_merged::HalfKaHmMergedStack;
use super::halfka_split::HalfKaSplitStack;
use super::halfkp::HalfKPStack;
use super::network::NNUENetwork;
use super::spec::ArchitectureSpec;
use super::stats::{count_already_computed, count_refresh, count_update};
use crate::position::Position;
use crate::types::Value;

/// NNUE 評価器（外部 API）
///
/// Network と Stack のペアリングを内部で保証する。
/// NNUE 評価の推奨経路として、低レベル API を直接使用するより安全。
///
/// # 設計
///
/// - `net` は `Arc` で共有（並列探索で複数スレッドが同じ重みを参照）
/// - `stack` はスレッド/探索文脈ごとに独立
/// - `acc_cache` は LayerStacks アーキテクチャ時のみ作成（Finny Tables）
///
/// # 使用方法
///
/// `new_with_position()` で局面を指定して作成し、即座に `evaluate()` 可能。
pub struct NNUEEvaluator {
    net: Arc<NNUENetwork>,
    stack: AccumulatorStackVariant,
    /// LayerStacks 用 AccumulatorCaches（Finny Tables）
    /// LayerStacks アーキテクチャ以外では None
    #[cfg(feature = "layerstack-arch")]
    acc_cache: Option<LayerStacksAccCache>,
    /// 非LayerStacks用 AccumulatorCaches（Finny Tables）
    /// HalfKP/HalfKaSplit/HalfKaHmMerged で使用。LayerStacks では None
    acc_cache_generic: Option<AccumulatorCacheGeneric>,
}

impl NNUEEvaluator {
    /// 局面を指定して評価器を作成
    ///
    /// 内部で `reset()` を呼び出すため、即座に `evaluate()` 可能。
    ///
    /// # 例
    ///
    /// ```ignore
    /// let mut evaluator = NNUEEvaluator::new_with_position(network, &position);
    /// let value = evaluator.evaluate(&position);  // 即座に評価可能
    /// ```
    pub fn new_with_position(net: Arc<NNUENetwork>, pos: &Position) -> Self {
        let stack = AccumulatorStackVariant::from_network(&net);
        #[cfg(feature = "layerstack-arch")]
        let acc_cache = if let NNUENetwork::LayerStacks(ls_net) = &*net {
            Some(ls_net.new_acc_cache())
        } else {
            None
        };
        let acc_cache_generic = Self::new_generic_cache(&net);
        let mut evaluator = Self {
            net,
            stack,
            #[cfg(feature = "layerstack-arch")]
            acc_cache,
            acc_cache_generic,
        };
        evaluator.reset(pos);
        evaluator
    }

    /// 並列探索用に評価器を複製し、指定局面で初期化
    ///
    /// 各スレッドで独立した探索状態を持つために使用。
    /// Network の重みは `Arc` で共有されるため、メモリ効率が良い。
    /// 内部で `reset()` まで行うため、即座に `evaluate()` 可能。
    ///
    /// # 引数
    ///
    /// - `pos`: 初期化する局面
    pub fn clone_for_thread(&self, pos: &Position) -> Self {
        #[cfg(feature = "layerstack-arch")]
        let acc_cache = if let NNUENetwork::LayerStacks(ls_net) = &*self.net {
            Some(ls_net.new_acc_cache())
        } else {
            None
        };
        let acc_cache_generic = Self::new_generic_cache(&self.net);
        let mut evaluator = Self {
            net: Arc::clone(&self.net),
            stack: AccumulatorStackVariant::from_network(&self.net),
            #[cfg(feature = "layerstack-arch")]
            acc_cache,
            acc_cache_generic,
        };
        evaluator.reset(pos);
        evaluator
    }

    // =========================================================================
    // 探索操作 API
    // =========================================================================

    /// スタックをリセット（探索開始時に呼び出す）
    ///
    /// ルート局面でアキュムレータをフル再計算する。
    ///
    /// # 引数
    ///
    /// - `pos`: リセット後の局面（アキュムレータ計算に使用）
    pub fn reset(&mut self, pos: &Position) {
        self.stack.reset();
        self.refresh_accumulator(pos);
    }

    /// 手を進める（do_move 時）
    ///
    /// アキュムレータスタックに新しいエントリをプッシュする。
    ///
    /// # 引数
    ///
    /// - `dirty_piece`: 指し手で変化した駒情報（差分更新に使用）
    #[inline]
    pub fn push(&mut self, dirty_piece: DirtyPiece) {
        self.stack.push(dirty_piece);
    }

    /// 手を戻す（undo_move 時）
    ///
    /// アキュムレータスタックから最新エントリをポップする。
    #[inline]
    pub fn pop(&mut self) {
        self.stack.pop();
    }

    /// 評価値を計算
    ///
    /// 必要に応じてアキュムレータを更新し、評価値を返す。
    ///
    /// # 引数
    ///
    /// - `pos`: 評価対象の局面
    ///
    /// # 戻り値
    ///
    /// 局面の評価値（手番側から見た評価値）
    #[inline(always)]
    pub fn evaluate(&mut self, pos: &Position) -> Value {
        // アキュムレータを更新（必要に応じて差分更新 or フル再計算）
        self.ensure_accumulator_computed(pos);

        // 評価
        self.evaluate_only(pos)
    }

    /// アキュムレータをフル再計算（ベンチマーク用）
    ///
    /// 通常は `reset()` を使用すること。
    /// ベンチマークでアキュムレータ計算のみを測定したい場合に使用。
    ///
    /// # 引数
    ///
    /// - `pos`: 計算対象の局面
    pub fn refresh(&mut self, pos: &Position) {
        self.refresh_accumulator(pos);
    }

    /// アキュムレータ更新なしで評価のみ実行（ベンチマーク用）
    ///
    /// アキュムレータが計算済みであることが前提。
    /// ベンチマークで評価部分のみを測定したい場合に使用。
    ///
    /// # 引数
    ///
    /// - `pos`: 評価対象の局面
    ///
    /// # 戻り値
    ///
    /// 局面の評価値（手番側から見た評価値）
    ///
    /// # 注意
    ///
    /// アキュムレータが未計算の場合、不正な評価値が返る。
    /// 通常は `evaluate()` を使用すること。
    #[inline(always)]
    pub fn evaluate_only(&self, pos: &Position) -> Value {
        match (&*self.net, &self.stack) {
            #[cfg(feature = "nnue-runtime-dimensions")]
            (
                NNUENetwork::DynamicLayerStacks(net),
                AccumulatorStackVariant::DynamicLayerStacks(st),
            ) => net.evaluate(pos, &mut st.borrow_mut()),
            #[cfg(feature = "nnue-runtime-dimensions")]
            (NNUENetwork::DynamicHalfKx(net), AccumulatorStackVariant::DynamicHalfKx(st)) => {
                net.evaluate(pos, &mut st.borrow_mut())
            }
            (NNUENetwork::HalfKaSplit(net), AccumulatorStackVariant::HalfKaSplit(st)) => {
                net.evaluate(pos, st)
            }
            (NNUENetwork::HalfKaHmMerged(net), AccumulatorStackVariant::HalfKaHmMerged(st)) => {
                net.evaluate(pos, st)
            }
            (NNUENetwork::HalfKaMerged(net), AccumulatorStackVariant::HalfKaMerged(st)) => {
                net.evaluate(pos, st)
            }
            (NNUENetwork::HalfKaHmSplit(net), AccumulatorStackVariant::HalfKaHmSplit(st)) => {
                net.evaluate(pos, st)
            }
            (NNUENetwork::HalfKP(net), AccumulatorStackVariant::HalfKP(st)) => {
                net.evaluate(pos, st)
            }
            #[cfg(feature = "layerstack-arch")]
            (NNUENetwork::LayerStacks(net), AccumulatorStackVariant::LayerStacks(st)) => {
                net.evaluate(pos, st)
            }
            _ => unreachable!("Network/Stack type mismatch"),
        }
    }

    // =========================================================================
    // 情報取得
    // =========================================================================

    /// アーキテクチャ名を取得
    pub fn architecture_name(&self) -> String {
        self.net.architecture_name()
    }

    /// アーキテクチャ仕様を取得
    pub fn architecture_spec(&self) -> ArchitectureSpec {
        self.net.architecture_spec()
    }

    /// ネットワークへの参照を取得
    pub fn network(&self) -> &Arc<NNUENetwork> {
        &self.net
    }

    /// L1 サイズを取得
    pub fn l1_size(&self) -> usize {
        self.net.l1_size()
    }

    // =========================================================================
    // 内部実装
    // =========================================================================

    fn new_generic_cache(net: &NNUENetwork) -> Option<AccumulatorCacheGeneric> {
        #[cfg(feature = "nnue-runtime-dimensions")]
        if matches!(net, NNUENetwork::DynamicHalfKx(_)) {
            return None;
        }
        if net.is_layer_stacks() {
            None
        } else {
            Some(AccumulatorCacheGeneric::new(net.l1_size()))
        }
    }

    /// アキュムレータをフル再計算
    fn refresh_accumulator(&mut self, pos: &Position) {
        match (&*self.net, &mut self.stack) {
            #[cfg(feature = "nnue-runtime-dimensions")]
            (
                NNUENetwork::DynamicLayerStacks(net),
                AccumulatorStackVariant::DynamicLayerStacks(st),
            ) => net.refresh(pos, st.get_mut()),
            #[cfg(feature = "nnue-runtime-dimensions")]
            (NNUENetwork::DynamicHalfKx(net), AccumulatorStackVariant::DynamicHalfKx(st)) => {
                net.refresh(pos, st.get_mut());
            }
            (NNUENetwork::HalfKaSplit(net), AccumulatorStackVariant::HalfKaSplit(st)) => {
                if let Some(cache) = &mut self.acc_cache_generic {
                    net.refresh_accumulator_with_cache(pos, st, cache);
                } else {
                    net.refresh_accumulator(pos, st);
                }
            }
            (NNUENetwork::HalfKaHmMerged(net), AccumulatorStackVariant::HalfKaHmMerged(st)) => {
                if let Some(cache) = &mut self.acc_cache_generic {
                    net.refresh_accumulator_with_cache(pos, st, cache);
                } else {
                    net.refresh_accumulator(pos, st);
                }
            }
            (NNUENetwork::HalfKaMerged(net), AccumulatorStackVariant::HalfKaMerged(st)) => {
                if let Some(cache) = &mut self.acc_cache_generic {
                    net.refresh_accumulator_with_cache(pos, st, cache);
                } else {
                    net.refresh_accumulator(pos, st);
                }
            }
            (NNUENetwork::HalfKaHmSplit(net), AccumulatorStackVariant::HalfKaHmSplit(st)) => {
                if let Some(cache) = &mut self.acc_cache_generic {
                    net.refresh_accumulator_with_cache(pos, st, cache);
                } else {
                    net.refresh_accumulator(pos, st);
                }
            }
            (NNUENetwork::HalfKP(net), AccumulatorStackVariant::HalfKP(st)) => {
                if let Some(cache) = &mut self.acc_cache_generic {
                    net.refresh_accumulator_with_cache(pos, st, cache);
                } else {
                    net.refresh_accumulator(pos, st);
                }
            }
            #[cfg(feature = "layerstack-arch")]
            (NNUENetwork::LayerStacks(net), AccumulatorStackVariant::LayerStacks(st)) => {
                net.update_accumulator(pos, st, &mut self.acc_cache);
            }
            _ => unreachable!("Network/Stack type mismatch"),
        }
    }

    /// アキュムレータが計算済みか確認し、必要に応じて更新
    fn ensure_accumulator_computed(&mut self, pos: &Position) {
        match (&*self.net, &mut self.stack) {
            #[cfg(feature = "nnue-runtime-dimensions")]
            (
                NNUENetwork::DynamicLayerStacks(net),
                AccumulatorStackVariant::DynamicLayerStacks(st),
            ) => net.ensure(pos, st.get_mut()),
            #[cfg(feature = "nnue-runtime-dimensions")]
            (NNUENetwork::DynamicHalfKx(net), AccumulatorStackVariant::DynamicHalfKx(st)) => {
                net.ensure(pos, st.get_mut());
            }
            (NNUENetwork::HalfKaSplit(net), AccumulatorStackVariant::HalfKaSplit(st)) => {
                Self::update_halfka_accumulator(net, pos, st, &mut self.acc_cache_generic);
            }
            (NNUENetwork::HalfKaHmMerged(net), AccumulatorStackVariant::HalfKaHmMerged(st)) => {
                Self::update_halfka_hm_accumulator(net, pos, st, &mut self.acc_cache_generic);
            }
            (NNUENetwork::HalfKaMerged(net), AccumulatorStackVariant::HalfKaMerged(st)) => {
                Self::update_halfka_merged_accumulator(net, pos, st, &mut self.acc_cache_generic);
            }
            (NNUENetwork::HalfKaHmSplit(net), AccumulatorStackVariant::HalfKaHmSplit(st)) => {
                Self::update_halfka_hm_split_accumulator(net, pos, st, &mut self.acc_cache_generic);
            }
            (NNUENetwork::HalfKP(net), AccumulatorStackVariant::HalfKP(st)) => {
                Self::update_halfkp_accumulator(net, pos, st, &mut self.acc_cache_generic);
            }
            #[cfg(feature = "layerstack-arch")]
            (NNUENetwork::LayerStacks(net), AccumulatorStackVariant::LayerStacks(st)) => {
                net.update_accumulator(pos, st, &mut self.acc_cache);
            }
            _ => unreachable!("Network/Stack type mismatch"),
        }
    }

    /// HalfKaSplit アキュムレータを更新
    #[inline]
    fn update_halfka_accumulator(
        net: &super::halfka_split::HalfKaSplitNetwork,
        pos: &Position,
        stack: &mut HalfKaSplitStack,
        cache: &mut Option<AccumulatorCacheGeneric>,
    ) {
        if stack.is_current_computed() {
            count_already_computed!();
            return;
        }

        let mut updated = false;

        // 直前局面で差分更新を試行
        if let Some(prev_idx) = stack.current_previous()
            && stack.is_entry_computed(prev_idx)
        {
            let dirty = stack.current_dirty_piece();
            if let Some(c) = cache {
                net.update_accumulator_with_cache(pos, &dirty, stack, prev_idx, c);
            } else {
                net.update_accumulator(pos, &dirty, stack, prev_idx);
            }
            count_update!();
            updated = true;
        }

        // 失敗なら全計算
        if !updated {
            if let Some(c) = cache {
                net.refresh_accumulator_with_cache(pos, stack, c);
            } else {
                net.refresh_accumulator(pos, stack);
            }
            count_refresh!();
        }
    }

    /// HalfKaHmMerged アキュムレータを更新
    #[inline]
    fn update_halfka_hm_accumulator(
        net: &super::halfka_hm_merged::HalfKaHmMergedNetwork,
        pos: &Position,
        stack: &mut HalfKaHmMergedStack,
        cache: &mut Option<AccumulatorCacheGeneric>,
    ) {
        if stack.is_current_computed() {
            count_already_computed!();
            return;
        }

        let mut updated = false;

        // 直前局面で差分更新を試行
        if let Some(prev_idx) = stack.current_previous()
            && stack.is_entry_computed(prev_idx)
        {
            let dirty = stack.current_dirty_piece();
            if let Some(c) = cache {
                net.update_accumulator_with_cache(pos, &dirty, stack, prev_idx, c);
            } else {
                net.update_accumulator(pos, &dirty, stack, prev_idx);
            }
            count_update!();
            updated = true;
        }

        // 失敗なら全計算
        if !updated {
            if let Some(c) = cache {
                net.refresh_accumulator_with_cache(pos, stack, c);
            } else {
                net.refresh_accumulator(pos, stack);
            }
            count_refresh!();
        }
    }

    /// HalfKaMerged アキュムレータを更新
    #[inline]
    fn update_halfka_merged_accumulator(
        net: &super::halfka_merged::HalfKaMergedNetwork,
        pos: &Position,
        stack: &mut super::halfka_merged::HalfKaMergedStack,
        cache: &mut Option<AccumulatorCacheGeneric>,
    ) {
        if stack.is_current_computed() {
            count_already_computed!();
            return;
        }

        let mut updated = false;

        if let Some(prev_idx) = stack.current_previous()
            && stack.is_entry_computed(prev_idx)
        {
            let dirty = stack.current_dirty_piece();
            if let Some(c) = cache {
                net.update_accumulator_with_cache(pos, &dirty, stack, prev_idx, c);
            } else {
                net.update_accumulator(pos, &dirty, stack, prev_idx);
            }
            count_update!();
            updated = true;
        }

        if !updated {
            if let Some(c) = cache {
                net.refresh_accumulator_with_cache(pos, stack, c);
            } else {
                net.refresh_accumulator(pos, stack);
            }
            count_refresh!();
        }
    }

    /// HalfKaHmSplit アキュムレータを更新
    #[inline]
    fn update_halfka_hm_split_accumulator(
        net: &super::halfka_hm_split::HalfKaHmSplitNetwork,
        pos: &Position,
        stack: &mut super::halfka_hm_split::HalfKaHmSplitStack,
        cache: &mut Option<AccumulatorCacheGeneric>,
    ) {
        if stack.is_current_computed() {
            count_already_computed!();
            return;
        }

        let mut updated = false;

        if let Some(prev_idx) = stack.current_previous()
            && stack.is_entry_computed(prev_idx)
        {
            let dirty = stack.current_dirty_piece();
            if let Some(c) = cache {
                net.update_accumulator_with_cache(pos, &dirty, stack, prev_idx, c);
            } else {
                net.update_accumulator(pos, &dirty, stack, prev_idx);
            }
            count_update!();
            updated = true;
        }

        if !updated {
            if let Some(c) = cache {
                net.refresh_accumulator_with_cache(pos, stack, c);
            } else {
                net.refresh_accumulator(pos, stack);
            }
            count_refresh!();
        }
    }

    /// HalfKP アキュムレータを更新
    #[inline]
    fn update_halfkp_accumulator(
        net: &super::halfkp::HalfKPNetwork,
        pos: &Position,
        stack: &mut HalfKPStack,
        cache: &mut Option<AccumulatorCacheGeneric>,
    ) {
        if stack.is_current_computed() {
            count_already_computed!();
            return;
        }

        let mut updated = false;

        // 直前局面で差分更新を試行
        if let Some(prev_idx) = stack.current_previous()
            && stack.is_entry_computed(prev_idx)
        {
            let dirty = stack.current_dirty_piece();
            if let Some(c) = cache {
                net.update_accumulator_with_cache(pos, &dirty, stack, prev_idx, c);
            } else {
                net.update_accumulator(pos, &dirty, stack, prev_idx);
            }
            count_update!();
            updated = true;
        }

        // 失敗なら全計算
        if !updated {
            if let Some(c) = cache {
                net.refresh_accumulator_with_cache(pos, stack, c);
            } else {
                net.refresh_accumulator(pos, stack);
            }
            count_refresh!();
        }
    }
}

#[cfg(test)]
mod tests {
    use super::*;

    /// NNUEEvaluator の基本的な構築テスト
    ///
    /// ネットワークなしでのテスト（構造確認のみ）
    #[test]
    fn test_evaluator_construction() {
        // デフォルトの AccumulatorStackVariant と同様の構造確認
        let stack = AccumulatorStackVariant::new_default();
        assert!(stack.is_halfkp());
    }

    /// push/pop の対称性テスト
    #[test]
    fn test_stack_push_pop() {
        let mut stack = AccumulatorStackVariant::new_default();
        let dirty = DirtyPiece::default();

        stack.reset();
        stack.push(dirty);
        stack.push(dirty);
        stack.pop();
        stack.pop();
        // パニックしなければ成功
    }

    /// NNUEEvaluator のサイズテスト
    #[test]
    fn test_evaluator_size() {
        use std::mem::size_of;

        let evaluator_size = size_of::<NNUEEvaluator>();
        let arc_size = size_of::<Arc<NNUENetwork>>();
        let stack_size = size_of::<AccumulatorStackVariant>();

        eprintln!("NNUEEvaluator size: {evaluator_size} bytes");
        eprintln!("Arc<NNUENetwork> size: {arc_size} bytes");
        eprintln!("AccumulatorStackVariant size: {stack_size} bytes");

        // Evaluator は Arc + Stack のサイズ程度
        assert!(evaluator_size > 0);
    }

    /// AccumulatorStackVariant::matches_network のテスト
    #[test]
    fn test_stack_variant_type_checking() {
        use crate::nnue::network_halfka_hm_merged::AccumulatorStackHalfKaHmMerged;
        use crate::nnue::network_halfka_split::AccumulatorStackHalfKaSplit;
        use crate::nnue::network_halfkp::AccumulatorStackHalfKP;

        // HalfKaSplit スタックの各 L1 サイズ
        let halfka_nm_l256 = AccumulatorStackVariant::HalfKaSplit(HalfKaSplitStack::L256(
            AccumulatorStackHalfKaSplit::<256>::new(),
        ));
        let halfka_nm_l512 = AccumulatorStackVariant::HalfKaSplit(HalfKaSplitStack::L512(
            AccumulatorStackHalfKaSplit::<512>::new(),
        ));
        let halfka_nm_l1024 = AccumulatorStackVariant::HalfKaSplit(HalfKaSplitStack::L1024(
            AccumulatorStackHalfKaSplit::<1024>::new(),
        ));

        // HalfKaHmMerged スタックの各 L1 サイズ
        let halfka_hm_l256 = AccumulatorStackVariant::HalfKaHmMerged(HalfKaHmMergedStack::L256(
            AccumulatorStackHalfKaHmMerged::<256>::new(),
        ));
        let halfka_hm_l512 = AccumulatorStackVariant::HalfKaHmMerged(HalfKaHmMergedStack::L512(
            AccumulatorStackHalfKaHmMerged::<512>::new(),
        ));
        let halfka_hm_l1024 = AccumulatorStackVariant::HalfKaHmMerged(HalfKaHmMergedStack::L1024(
            AccumulatorStackHalfKaHmMerged::<1024>::new(),
        ));

        // HalfKP スタックの各 L1 サイズ
        let halfkp_l256 = AccumulatorStackVariant::HalfKP(HalfKPStack::L256(
            AccumulatorStackHalfKP::<256>::new(),
        ));
        let halfkp_l512 = AccumulatorStackVariant::HalfKP(HalfKPStack::L512(
            AccumulatorStackHalfKP::<512>::new(),
        ));

        // 型の確認
        assert!(matches!(halfka_nm_l256, AccumulatorStackVariant::HalfKaSplit(_)));
        assert!(matches!(halfka_nm_l512, AccumulatorStackVariant::HalfKaSplit(_)));
        assert!(matches!(halfka_nm_l1024, AccumulatorStackVariant::HalfKaSplit(_)));
        assert!(matches!(halfka_hm_l256, AccumulatorStackVariant::HalfKaHmMerged(_)));
        assert!(matches!(halfka_hm_l512, AccumulatorStackVariant::HalfKaHmMerged(_)));
        assert!(matches!(halfka_hm_l1024, AccumulatorStackVariant::HalfKaHmMerged(_)));
        assert!(matches!(halfkp_l256, AccumulatorStackVariant::HalfKP(_)));
        assert!(matches!(halfkp_l512, AccumulatorStackVariant::HalfKP(_)));

        // is_halfkp() の確認
        assert!(!halfka_nm_l256.is_halfkp());
        assert!(!halfka_nm_l512.is_halfkp());
        assert!(!halfka_nm_l1024.is_halfkp());
        assert!(!halfka_hm_l256.is_halfkp());
        assert!(!halfka_hm_l512.is_halfkp());
        assert!(!halfka_hm_l1024.is_halfkp());
        assert!(halfkp_l256.is_halfkp());
        assert!(halfkp_l512.is_halfkp());
    }

    /// 各バリアントの push/pop インデックス一貫性テスト
    ///
    /// LayerStacks の各 L1 バリアント（1536/768/512）について、有効な feature のものだけ
    /// 個別に検証する。旧実装は 1536 のみ `#[cfg]` 付き `let` だったため、1536 無効
    /// ビルドでは後続の `stack.reset()/push()/pop()` が直前の HalfKP に対して暗黙に
    /// 実行され、LayerStacks variant を実質テストしない silent no-op 状態だった。
    #[test]
    fn test_all_variants_push_pop_consistency() {
        use crate::nnue::network_halfka_hm_merged::AccumulatorStackHalfKaHmMerged;
        use crate::nnue::network_halfka_split::AccumulatorStackHalfKaSplit;
        use crate::nnue::network_halfkp::AccumulatorStackHalfKP;

        let dirty = DirtyPiece::default();

        // HalfKaSplit L512
        let mut stack = AccumulatorStackVariant::HalfKaSplit(HalfKaSplitStack::L512(
            AccumulatorStackHalfKaSplit::<512>::new(),
        ));
        stack.reset();
        stack.push(dirty);
        stack.push(dirty);
        stack.pop();
        stack.pop();
        // パニックしなければ成功

        // HalfKaHmMerged L512
        let mut stack = AccumulatorStackVariant::HalfKaHmMerged(HalfKaHmMergedStack::L512(
            AccumulatorStackHalfKaHmMerged::<512>::new(),
        ));
        stack.reset();
        stack.push(dirty);
        stack.push(dirty);
        stack.pop();
        stack.pop();
        // パニックしなければ成功

        // HalfKP L512
        let mut stack = AccumulatorStackVariant::HalfKP(HalfKPStack::L512(
            AccumulatorStackHalfKP::<512>::new(),
        ));
        stack.reset();
        stack.push(dirty);
        stack.push(dirty);
        stack.pop();
        stack.pop();
        // パニックしなければ成功

        // LayerStacks 各 L1 バリアント（有効 feature のみ検証）。
        // 外側の `any(...)` でいずれかの variant が有効なときだけ import が使われる
        // ようにして unused-import 警告を抑える。
        #[cfg(all(
            feature = "layerstack-arch",
            any(
                feature = "layerstacks-1536x16x32",
                feature = "layerstacks-1536x32x32",
                feature = "layerstacks-768x16x32",
                feature = "layerstacks-768x8x32",
                feature = "layerstacks-512x16x32",
                feature = "layerstacks-1024x16x32",
                feature = "layerstacks-3072x16x32"
            )
        ))]
        {
            use crate::nnue::accumulator_layer_stacks::{
                AccumulatorStackLayerStacks, LayerStacksAccStack,
            };

            #[cfg(feature = "layerstacks-1536x16x32")]
            {
                let mut stack = AccumulatorStackVariant::LayerStacks(
                    LayerStacksAccStack::L1536x16x32(AccumulatorStackLayerStacks::<1536>::new()),
                );
                stack.reset();
                stack.push(dirty);
                stack.push(dirty);
                stack.pop();
                stack.pop();
            }

            #[cfg(feature = "layerstacks-1536x32x32")]
            {
                let mut stack = AccumulatorStackVariant::LayerStacks(
                    LayerStacksAccStack::L1536x32x32(AccumulatorStackLayerStacks::<1536>::new()),
                );
                stack.reset();
                stack.push(dirty);
                stack.push(dirty);
                stack.pop();
                stack.pop();
            }

            #[cfg(feature = "layerstacks-768x16x32")]
            {
                let mut stack = AccumulatorStackVariant::LayerStacks(
                    LayerStacksAccStack::L768x16x32(AccumulatorStackLayerStacks::<768>::new()),
                );
                stack.reset();
                stack.push(dirty);
                stack.push(dirty);
                stack.pop();
                stack.pop();
            }

            #[cfg(feature = "layerstacks-768x8x32")]
            {
                let mut stack = AccumulatorStackVariant::LayerStacks(
                    LayerStacksAccStack::L768x8x32(AccumulatorStackLayerStacks::<768>::new()),
                );
                stack.reset();
                stack.push(dirty);
                stack.push(dirty);
                stack.pop();
                stack.pop();
            }

            #[cfg(feature = "layerstacks-512x16x32")]
            {
                let mut stack = AccumulatorStackVariant::LayerStacks(
                    LayerStacksAccStack::L512x16x32(AccumulatorStackLayerStacks::<512>::new()),
                );
                stack.reset();
                stack.push(dirty);
                stack.push(dirty);
                stack.pop();
                stack.pop();
            }

            #[cfg(feature = "layerstacks-1024x16x32")]
            {
                let mut stack = AccumulatorStackVariant::LayerStacks(
                    LayerStacksAccStack::L1024x16x32(AccumulatorStackLayerStacks::<1024>::new()),
                );
                stack.reset();
                stack.push(dirty);
                stack.push(dirty);
                stack.pop();
                stack.pop();
            }

            #[cfg(feature = "layerstacks-3072x16x32")]
            {
                let mut stack = AccumulatorStackVariant::LayerStacks(
                    LayerStacksAccStack::L3072x16x32(AccumulatorStackLayerStacks::<3072>::new()),
                );
                stack.reset();
                stack.push(dirty);
                stack.push(dirty);
                stack.pop();
                stack.pop();
            }
        }
    }

    /// 深い探索木での push/pop テスト
    #[test]
    fn test_deep_search_simulation() {
        let mut stack = AccumulatorStackVariant::new_default();
        let dirty = DirtyPiece::default();

        stack.reset();

        // 典型的な探索深さ (30手程度)
        const MAX_DEPTH: usize = 30;

        // 複数回の探索をシミュレート
        for _ in 0..5 {
            // 探索開始
            for _ in 0..MAX_DEPTH {
                stack.push(dirty);
            }

            // 探索終了
            for _ in 0..MAX_DEPTH {
                stack.pop();
            }
        }

        // パニックしなければ成功
    }

    /// network.rs の NNUENetwork enum が全アーキテクチャをカバーしていることの確認
    #[test]
    fn test_network_enum_coverage() {
        use crate::nnue::halfka_hm_merged::HalfKaHmMergedNetwork;
        use crate::nnue::halfka_split::HalfKaSplitNetwork;
        use crate::nnue::halfkp::HalfKPNetwork;

        // HalfKaSplit サポートアーキテクチャ数
        let halfka_specs = HalfKaSplitNetwork::supported_specs();
        assert_eq!(halfka_specs.len(), 24); // (256:1 + 512:3 + 768:1 + 1024:3) × 3 活性化

        // HalfKaHmMerged サポートアーキテクチャ数
        let halfka_hm_specs = HalfKaHmMergedNetwork::supported_specs();
        assert_eq!(halfka_hm_specs.len(), 24); // (256:1 + 512:3 + 768:1 + 1024:3) × 3 活性化

        // HalfKP サポートアーキテクチャ数
        let halfkp_specs = HalfKPNetwork::supported_specs();
        assert_eq!(halfkp_specs.len(), 21); // (256:1 + 512:3 + 768:1 + 1024:2) × 3 活性化

        // 全アーキテクチャで feature_set が正しいことを確認
        for spec in &halfka_specs {
            assert_eq!(
                spec.feature_set,
                crate::nnue::spec::FeatureSet::HalfKaSplit,
                "HalfKaSplit spec has wrong feature_set: {spec:?}"
            );
        }

        for spec in &halfka_hm_specs {
            assert_eq!(
                spec.feature_set,
                crate::nnue::spec::FeatureSet::HalfKaHmMerged,
                "HalfKaHmMerged spec has wrong feature_set: {spec:?}"
            );
        }

        for spec in &halfkp_specs {
            assert_eq!(
                spec.feature_set,
                crate::nnue::spec::FeatureSet::HalfKP,
                "HalfKP spec has wrong feature_set: {spec:?}"
            );
        }
    }
}

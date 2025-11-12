# 16. 算法理论 (Algorithm Theory)

## 📋 目录

- [1 模块概述](#1-模块概述)
- [2 核心理论](#2-核心理论)
  - [2.1 算法设计理论](#21-算法设计理论)
  - [2.2 复杂度理论](#22-复杂度理论)
  - [2.3 算法设计模式](#23-算法设计模式)
- [3 Rust实现](#3-rust实现)
  - [3.1 算法设计模式实现](#31-算法设计模式实现)
  - [3.2 复杂度分析实现](#32-复杂度分析实现)
  - [3.3 数据结构实现](#33-数据结构实现)
- [4 应用示例](#4-应用示例)
  - [4.1 示例1：排序算法比较](#41-示例1排序算法比较)
  - [4.2 示例2：图算法应用](#42-示例2图算法应用)
  - [4.3 示例3：动态规划应用](#43-示例3动态规划应用)
- [5 理论扩展](#5-理论扩展)
  - [5.1 并行算法理论](#51-并行算法理论)
  - [5.2 随机算法理论](#52-随机算法理论)
  - [5.3 近似算法理论](#53-近似算法理论)
- [6 批判性分析](#6-批判性分析)
  - [6.1 多元理论视角](#61-多元理论视角)
  - [6.2 局限性分析](#62-局限性分析)
  - [6.3 争议与分歧](#63-争议与分歧)
  - [6.4 应用前景](#64-应用前景)
  - [6.5 改进建议](#65-改进建议)

---

## 1 模块概述

算法理论是计算机科学的核心基础，研究算法的设计、分析、优化和复杂度。本模块涵盖算法设计方法、复杂度理论、数据结构、并行算法等核心概念，为高效计算和问题求解提供理论基础。

## 🏗️ 目录结构

```text
16_Algorithm_Theory/
├── README.md                           # 模块总览
├── 01_Algorithm_Foundation_Theory.md   # 算法基础理论
├── 16.1_Fundamentals/                  # 基础理论
│   ├── 16.1.1_Algorithm_Design.md     # 算法设计
│   ├── 16.1.2_Complexity_Analysis.md  # 复杂度分析
│   └── 16.1.3_Data_Structures.md     # 数据结构
├── 16.2_Complexity_Theory/             # 复杂度理论
│   ├── 16.2.1_Time_Complexity.md      # 时间复杂度
│   ├── 16.2.2_Space_Complexity.md     # 空间复杂度
│   └── 16.2.3_Asymptotic_Analysis.md  # 渐进分析
├── 16.3_Optimization_Theory/           # 优化理论
│   ├── 16.3.1_Algorithm_Optimization.md # 算法优化
│   ├── 16.3.2_Parallel_Algorithms.md   # 并行算法
│   └── 16.3.3_Distributed_Algorithms.md # 分布式算法
├── 16.4_Design_Patterns/               # 设计模式
├── 16.5_Advanced_Algorithms/           # 高级算法
└── 16.6_Algorithm_Analysis/            # 算法分析
```

## 2 核心理论

### 2.1 算法设计理论

**定义 16.1.1** (算法)
算法是解决特定问题的有限步骤序列，表示为 $A = (I, O, P)$，其中：

- $I$ 是输入集合
- $O$ 是输出集合  
- $P$ 是处理步骤

**定义 16.1.2** (算法正确性)
算法 $A$ 对于问题 $P$ 是正确的，当且仅当：
$\forall x \in I, A(x) \in O \land P(x, A(x))$

**定理 16.1.1** (算法终止性)
确定性算法在有限时间内终止。

### 2.2 复杂度理论

**定义 16.2.1** (时间复杂度)
算法 $A$ 的时间复杂度函数 $T_A: \mathbb{N} \rightarrow \mathbb{N}$ 定义为：
$T_A(n) = \max\{t_A(x) \mid |x| = n\}$

**定义 16.2.2** (空间复杂度)
算法 $A$ 的空间复杂度函数 $S_A: \mathbb{N} \rightarrow \mathbb{N}$ 定义为：
$S_A(n) = \max\{s_A(x) \mid |x| = n\}$

**定理 16.2.1** (复杂度关系)
对于任意算法 $A$，$T_A(n) \geq S_A(n)$

### 2.3 算法设计模式

**定义 16.3.1** (分治法)
分治法将问题分解为子问题：$T(n) = aT(n/b) + f(n)$

**定义 16.3.2** (动态规划)
动态规划通过子问题重叠求解：$T(n) = \sum_{i=1}^k T(n_i) + O(1)$

**定义 16.3.3** (贪心算法)
贪心算法在每一步选择局部最优解。

## 3 Rust实现

### 3.1 算法设计模式实现

```rust
use std::cmp::Ordering;
use std::collections::{BinaryHeap, HashMap, HashSet};
use std::fmt;

/// 算法特征
pub trait Algorithm<I, O> {
    fn solve(&self, input: I) -> O;
    fn time_complexity(&self, n: usize) -> f64;
    fn space_complexity(&self, n: usize) -> f64;
}

/// 分治法实现
pub struct DivideAndConquer;

impl DivideAndConquer {
    /// 归并排序
    pub fn merge_sort<T: Ord + Clone>(arr: &[T]) -> Vec<T> {
        if arr.len() <= 1 {
            return arr.to_vec();
        }
        
        let mid = arr.len() / 2;
        let left = Self::merge_sort(&arr[..mid]);
        let right = Self::merge_sort(&arr[mid..]);
        
        Self::merge(left, right)
    }
    
    fn merge<T: Ord + Clone>(left: Vec<T>, right: Vec<T>) -> Vec<T> {
        let mut result = Vec::new();
        let mut left_iter = left.into_iter();
        let mut right_iter = right.into_iter();
        let mut left_peek = left_iter.next();
        let mut right_peek = right_iter.next();
        
        while let (Some(l), Some(r)) = (&left_peek, &right_peek) {
            match l.cmp(r) {
                Ordering::Less | Ordering::Equal => {
                    result.push(left_peek.take().unwrap());
                    left_peek = left_iter.next();
                }
                Ordering::Greater => {
                    result.push(right_peek.take().unwrap());
                    right_peek = right_iter.next();
                }
            }
        }
        
        // 添加剩余元素
        if let Some(l) = left_peek {
            result.push(l);
        }
        if let Some(r) = right_peek {
            result.push(r);
        }
        
        result.extend(left_iter);
        result.extend(right_iter);
        result
    }
    
    /// 快速排序
    pub fn quick_sort<T: Ord + Clone>(arr: &[T]) -> Vec<T> {
        if arr.len() <= 1 {
            return arr.to_vec();
        }
        
        let pivot = &arr[0];
        let (less, equal, greater): (Vec<_>, Vec<_>, Vec<_>) = arr.iter()
            .partition(|&x| x < pivot);
        
        let mut result = Self::quick_sort(&less);
        result.extend(equal);
        result.extend(Self::quick_sort(&greater));
        result
    }
}

/// 动态规划实现
pub struct DynamicProgramming;

impl DynamicProgramming {
    /// 斐波那契数列
    pub fn fibonacci(n: usize) -> u64 {
        if n <= 1 {
            return n as u64;
        }
        
        let mut dp = vec![0; n + 1];
        dp[0] = 0;
        dp[1] = 1;
        
        for i in 2..=n {
            dp[i] = dp[i-1] + dp[i-2];
        }
        
        dp[n]
    }
    
    /// 最长公共子序列
    pub fn longest_common_subsequence(s1: &str, s2: &str) -> String {
        let chars1: Vec<char> = s1.chars().collect();
        let chars2: Vec<char> = s2.chars().collect();
        let m = chars1.len();
        let n = chars2.len();
        
        let mut dp = vec![vec![0; n + 1]; m + 1];
        
        // 填充DP表
        for i in 1..=m {
            for j in 1..=n {
                if chars1[i-1] == chars2[j-1] {
                    dp[i][j] = dp[i-1][j-1] + 1;
                } else {
                    dp[i][j] = dp[i-1][j].max(dp[i][j-1]);
                }
            }
        }
        
        // 回溯构造结果
        let mut result = String::new();
        let mut i = m;
        let mut j = n;
        
        while i > 0 && j > 0 {
            if chars1[i-1] == chars2[j-1] {
                result.insert(0, chars1[i-1]);
                i -= 1;
                j -= 1;
            } else if dp[i-1][j] > dp[i][j-1] {
                i -= 1;
            } else {
                j -= 1;
            }
        }
        
        result
    }
    
    /// 0-1背包问题
    pub fn knapsack_01(weights: &[usize], values: &[usize], capacity: usize) -> usize {
        let n = weights.len();
        let mut dp = vec![vec![0; capacity + 1]; n + 1];
        
        for i in 1..=n {
            for w in 0..=capacity {
                if weights[i-1] <= w {
                    dp[i][w] = dp[i-1][w].max(dp[i-1][w - weights[i-1]] + values[i-1]);
                } else {
                    dp[i][w] = dp[i-1][w];
                }
            }
        }
        
        dp[n][capacity]
    }
}

/// 贪心算法实现
pub struct GreedyAlgorithm;

impl GreedyAlgorithm {
    /// 活动选择问题
    pub fn activity_selection(activities: &[(usize, usize)]) -> Vec<usize> {
        let mut sorted_activities: Vec<(usize, usize, usize)> = activities
            .iter()
            .enumerate()
            .map(|(i, &(start, end))| (start, end, i))
            .collect();
        
        sorted_activities.sort_by_key(|&(_, end, _)| end);
        
        let mut selected = Vec::new();
        let mut last_end = 0;
        
        for (start, end, index) in sorted_activities {
            if start >= last_end {
                selected.push(index);
                last_end = end;
            }
        }
        
        selected
    }
    
    /// 霍夫曼编码
    pub fn huffman_encoding(frequencies: &[usize]) -> HashMap<char, String> {
        #[derive(PartialEq, Eq)]
        struct HuffmanNode {
            frequency: usize,
            character: Option<char>,
            left: Option<Box<HuffmanNode>>,
            right: Option<Box<HuffmanNode>>,
        }
        
        impl PartialOrd for HuffmanNode {
            fn partial_cmp(&self, other: &Self) -> Option<Ordering> {
                Some(self.frequency.cmp(&other.frequency).reverse())
            }
        }
        
        impl Ord for HuffmanNode {
            fn cmp(&self, other: &Self) -> Ordering {
                self.frequency.cmp(&other.frequency).reverse()
            }
        }
        
        // 构建霍夫曼树
        let mut heap = BinaryHeap::new();
        for (i, &freq) in frequencies.iter().enumerate() {
            if freq > 0 {
                heap.push(HuffmanNode {
                    frequency: freq,
                    character: Some((b'a' + i as u8) as char),
                    left: None,
                    right: None,
                });
            }
        }
        
        while heap.len() > 1 {
            let left = heap.pop().unwrap();
            let right = heap.pop().unwrap();
            
            heap.push(HuffmanNode {
                frequency: left.frequency + right.frequency,
                character: None,
                left: Some(Box::new(left)),
                right: Some(Box::new(right)),
            });
        }
        
        // 生成编码
        let mut codes = HashMap::new();
        fn generate_codes(node: &HuffmanNode, code: String, codes: &mut HashMap<char, String>) {
            if let Some(ch) = node.character {
                codes.insert(ch, code);
            } else {
                if let Some(ref left) = node.left {
                    generate_codes(left, code.clone() + "0", codes);
                }
                if let Some(ref right) = node.right {
                    generate_codes(right, code + "1", codes);
                }
            }
        }
        
        if let Some(root) = heap.pop() {
            generate_codes(&root, String::new(), &mut codes);
        }
        
        codes
    }
}

/// 回溯算法实现
pub struct Backtracking;

impl Backtracking {
    /// N皇后问题
    pub fn n_queens(n: usize) -> Vec<Vec<String>> {
        let mut solutions = Vec::new();
        let mut board = vec![vec![false; n]; n];
        
        fn is_safe(board: &[Vec<bool>], row: usize, col: usize) -> bool {
            let n = board.len();
            
            // 检查行
            for j in 0..n {
                if board[row][j] {
                    return false;
                }
            }
            
            // 检查列
            for i in 0..n {
                if board[i][col] {
                    return false;
                }
            }
            
            // 检查对角线
            for i in 0..n {
                for j in 0..n {
                    if board[i][j] && (i + j == row + col || i as i32 - j as i32 == row as i32 - col as i32) {
                        return false;
                    }
                }
            }
            
            true
        }
        
        fn solve_n_queens(board: &mut Vec<Vec<bool>>, row: usize, solutions: &mut Vec<Vec<String>>) {
            let n = board.len();
            
            if row >= n {
                // 找到解
                let mut solution = Vec::new();
                for i in 0..n {
                    let mut row_str = String::new();
                    for j in 0..n {
                        if board[i][j] {
                            row_str.push('Q');
                        } else {
                            row_str.push('.');
                        }
                    }
                    solution.push(row_str);
                }
                solutions.push(solution);
                return;
            }
            
            for col in 0..n {
                if is_safe(board, row, col) {
                    board[row][col] = true;
                    solve_n_queens(board, row + 1, solutions);
                    board[row][col] = false;
                }
            }
        }
        
        solve_n_queens(&mut board, 0, &mut solutions);
        solutions
    }
    
    /// 子集和问题
    pub fn subset_sum(nums: &[i32], target: i32) -> Vec<Vec<i32>> {
        let mut solutions = Vec::new();
        let mut current = Vec::new();
        
        fn backtrack(nums: &[i32], target: i32, start: usize, current: &mut Vec<i32>, solutions: &mut Vec<Vec<i32>>) {
            let sum: i32 = current.iter().sum();
            
            if sum == target {
                solutions.push(current.clone());
                return;
            }
            
            if sum > target {
                return;
            }
            
            for i in start..nums.len() {
                current.push(nums[i]);
                backtrack(nums, target, i + 1, current, solutions);
                current.pop();
            }
        }
        
        backtrack(nums, target, 0, &mut current, &mut solutions);
        solutions
    }
}
```

### 3.2 复杂度分析实现

```rust
use std::time::{Duration, Instant};

/// 复杂度分析器
#[derive(Debug)]
pub struct ComplexityAnalyzer {
    pub measurements: Vec<(usize, Duration)>,
}

impl ComplexityAnalyzer {
    pub fn new() -> Self {
        ComplexityAnalyzer {
            measurements: Vec::new(),
        }
    }
    
    /// 测量算法性能
    pub fn measure<F, T>(&mut self, input_size: usize, algorithm: F) -> Duration 
    where F: FnOnce() -> T {
        let start = Instant::now();
        algorithm();
        let duration = start.elapsed();
        
        self.measurements.push((input_size, duration));
        duration
    }
    
    /// 分析时间复杂度
    pub fn analyze_time_complexity(&self) -> TimeComplexity {
        if self.measurements.len() < 2 {
            return TimeComplexity::Unknown;
        }
        
        let mut ratios = Vec::new();
        for i in 1..self.measurements.len() {
            let (n1, t1) = self.measurements[i-1];
            let (n2, t2) = self.measurements[i];
            
            let ratio = (t2.as_nanos() as f64) / (t1.as_nanos() as f64);
            let size_ratio = (n2 as f64) / (n1 as f64);
            let complexity_ratio = ratio / size_ratio;
            
            ratios.push(complexity_ratio);
        }
        
        let avg_ratio = ratios.iter().sum::<f64>() / ratios.len() as f64;
        
        if avg_ratio < 1.5 {
            TimeComplexity::O1
        } else if avg_ratio < 2.5 {
            TimeComplexity::OLogN
        } else if avg_ratio < 4.0 {
            TimeComplexity::ON
        } else if avg_ratio < 8.0 {
            TimeComplexity::ONLogN
        } else if avg_ratio < 16.0 {
            TimeComplexity::ON2
        } else {
            TimeComplexity::OExponential
        }
    }
    
    /// 估算大O复杂度
    pub fn estimate_big_o(&self) -> String {
        match self.analyze_time_complexity() {
            TimeComplexity::O1 => "O(1)".to_string(),
            TimeComplexity::OLogN => "O(log n)".to_string(),
            TimeComplexity::ON => "O(n)".to_string(),
            TimeComplexity::ONLogN => "O(n log n)".to_string(),
            TimeComplexity::ON2 => "O(n²)".to_string(),
            TimeComplexity::OExponential => "O(2ⁿ)".to_string(),
            TimeComplexity::Unknown => "Unknown".to_string(),
        }
    }
}

#[derive(Debug)]
pub enum TimeComplexity {
    O1,
    OLogN,
    ON,
    ONLogN,
    ON2,
    OExponential,
    Unknown,
}

/// 算法基准测试
#[derive(Debug)]
pub struct AlgorithmBenchmark {
    pub analyzer: ComplexityAnalyzer,
}

impl AlgorithmBenchmark {
    pub fn new() -> Self {
        AlgorithmBenchmark {
            analyzer: ComplexityAnalyzer::new(),
        }
    }
    
    /// 基准测试排序算法
    pub fn benchmark_sorting_algorithms(&mut self, max_size: usize) -> HashMap<String, String> {
        let mut results = HashMap::new();
        
        // 测试不同大小的输入
        for size in [100, 1000, 10000] {
            if size > max_size {
                break;
            }
            
            let mut data: Vec<i32> = (0..size).collect();
            data.reverse(); // 最坏情况
            
            // 测试归并排序
            self.analyzer.measure(size, || {
                let _ = DivideAndConquer::merge_sort(&data);
            });
        }
        results.insert("Merge Sort".to_string(), self.analyzer.estimate_big_o());
        
        // 重置分析器
        self.analyzer = ComplexityAnalyzer::new();
        
        // 测试快速排序
        for size in [100, 1000, 10000] {
            if size > max_size {
                break;
            }
            
            let mut data: Vec<i32> = (0..size).collect();
            data.reverse();
            
            self.analyzer.measure(size, || {
                let _ = DivideAndConquer::quick_sort(&data);
            });
        }
        results.insert("Quick Sort".to_string(), self.analyzer.estimate_big_o());
        
        results
    }
    
    /// 基准测试搜索算法
    pub fn benchmark_search_algorithms(&mut self, max_size: usize) -> HashMap<String, String> {
        let mut results = HashMap::new();
        
        for size in [100, 1000, 10000] {
            if size > max_size {
                break;
            }
            
            let data: Vec<i32> = (0..size).collect();
            let target = size as i32 - 1; // 查找最后一个元素
            
            self.analyzer.measure(size, || {
                let _ = data.binary_search(&target);
            });
        }
        results.insert("Binary Search".to_string(), self.analyzer.estimate_big_o());
        
        results
    }
}
```

### 3.3 数据结构实现

```rust
use std::collections::{HashMap, HashSet};
use std::fmt;

/// 二叉树节点
#[derive(Debug)]
pub struct TreeNode<T> {
    pub value: T,
    pub left: Option<Box<TreeNode<T>>>,
    pub right: Option<Box<TreeNode<T>>>,
}

impl<T> TreeNode<T> {
    pub fn new(value: T) -> Self {
        TreeNode {
            value,
            left: None,
            right: None,
        }
    }
}

/// 二叉搜索树
#[derive(Debug)]
pub struct BinarySearchTree<T: Ord> {
    pub root: Option<Box<TreeNode<T>>>,
}

impl<T: Ord> BinarySearchTree<T> {
    pub fn new() -> Self {
        BinarySearchTree { root: None }
    }
    
    /// 插入节点
    pub fn insert(&mut self, value: T) {
        self.root = Some(self.insert_recursive(self.root.take(), value));
    }
    
    fn insert_recursive(&self, node: Option<Box<TreeNode<T>>>, value: T) -> Box<TreeNode<T>> {
        match node {
            None => Box::new(TreeNode::new(value)),
            Some(mut node) => {
                if value < node.value {
                    node.left = Some(self.insert_recursive(node.left.take(), value));
                } else if value > node.value {
                    node.right = Some(self.insert_recursive(node.right.take(), value));
                }
                node
            }
        }
    }
    
    /// 查找节点
    pub fn search(&self, value: &T) -> Option<&T> {
        self.search_recursive(self.root.as_ref(), value)
    }
    
    fn search_recursive<'a>(&'a self, node: Option<&'a Box<TreeNode<T>>>, value: &T) -> Option<&'a T> {
        match node {
            None => None,
            Some(node) => {
                if value < &node.value {
                    self.search_recursive(node.left.as_ref(), value)
                } else if value > &node.value {
                    self.search_recursive(node.right.as_ref(), value)
                } else {
                    Some(&node.value)
                }
            }
        }
    }
    
    /// 中序遍历
    pub fn inorder_traversal(&self) -> Vec<&T> {
        let mut result = Vec::new();
        self.inorder_recursive(self.root.as_ref(), &mut result);
        result
    }
    
    fn inorder_recursive<'a>(&'a self, node: Option<&'a Box<TreeNode<T>>>, result: &mut Vec<&'a T>) {
        if let Some(node) = node {
            self.inorder_recursive(node.left.as_ref(), result);
            result.push(&node.value);
            self.inorder_recursive(node.right.as_ref(), result);
        }
    }
}

/// 图数据结构
#[derive(Debug)]
pub struct Graph {
    pub adjacency_list: HashMap<usize, Vec<usize>>,
    pub directed: bool,
}

impl Graph {
    pub fn new(directed: bool) -> Self {
        Graph {
            adjacency_list: HashMap::new(),
            directed,
        }
    }
    
    /// 添加边
    pub fn add_edge(&mut self, from: usize, to: usize) {
        self.adjacency_list.entry(from).or_insert_with(Vec::new).push(to);
        
        if !self.directed {
            self.adjacency_list.entry(to).or_insert_with(Vec::new).push(from);
        }
    }
    
    /// 深度优先搜索
    pub fn dfs(&self, start: usize) -> Vec<usize> {
        let mut visited = HashSet::new();
        let mut result = Vec::new();
        self.dfs_recursive(start, &mut visited, &mut result);
        result
    }
    
    fn dfs_recursive(&self, node: usize, visited: &mut HashSet<usize>, result: &mut Vec<usize>) {
        if visited.contains(&node) {
            return;
        }
        
        visited.insert(node);
        result.push(node);
        
        if let Some(neighbors) = self.adjacency_list.get(&node) {
            for &neighbor in neighbors {
                self.dfs_recursive(neighbor, visited, result);
            }
        }
    }
    
    /// 广度优先搜索
    pub fn bfs(&self, start: usize) -> Vec<usize> {
        let mut visited = HashSet::new();
        let mut result = Vec::new();
        let mut queue = std::collections::VecDeque::new();
        
        queue.push_back(start);
        visited.insert(start);
        
        while let Some(node) = queue.pop_front() {
            result.push(node);
            
            if let Some(neighbors) = self.adjacency_list.get(&node) {
                for &neighbor in neighbors {
                    if !visited.contains(&neighbor) {
                        visited.insert(neighbor);
                        queue.push_back(neighbor);
                    }
                }
            }
        }
        
        result
    }
    
    /// 拓扑排序
    pub fn topological_sort(&self) -> Result<Vec<usize>, String> {
        if !self.directed {
            return Err("Topological sort requires directed graph".to_string());
        }
        
        let mut in_degree = HashMap::new();
        let mut result = Vec::new();
        let mut queue = std::collections::VecDeque::new();
        
        // 计算入度
        for (node, neighbors) in &self.adjacency_list {
            in_degree.entry(*node).or_insert(0);
            for &neighbor in neighbors {
                *in_degree.entry(neighbor).or_insert(0) += 1;
            }
        }
        
        // 找到入度为0的节点
        for (node, &degree) in &in_degree {
            if degree == 0 {
                queue.push_back(*node);
            }
        }
        
        // 拓扑排序
        while let Some(node) = queue.pop_front() {
            result.push(node);
            
            if let Some(neighbors) = self.adjacency_list.get(&node) {
                for &neighbor in neighbors {
                    if let Some(degree) = in_degree.get_mut(&neighbor) {
                        *degree -= 1;
                        if *degree == 0 {
                            queue.push_back(neighbor);
                        }
                    }
                }
            }
        }
        
        if result.len() == in_degree.len() {
            Ok(result)
        } else {
            Err("Graph contains cycle".to_string())
        }
    }
}

/// 并查集
#[derive(Debug)]
pub struct UnionFind {
    pub parent: Vec<usize>,
    pub rank: Vec<usize>,
}

impl UnionFind {
    pub fn new(size: usize) -> Self {
        UnionFind {
            parent: (0..size).collect(),
            rank: vec![0; size],
        }
    }
    
    /// 查找根节点
    pub fn find(&mut self, x: usize) -> usize {
        if self.parent[x] != x {
            self.parent[x] = self.find(self.parent[x]);
        }
        self.parent[x]
    }
    
    /// 合并两个集合
    pub fn union(&mut self, x: usize, y: usize) {
        let root_x = self.find(x);
        let root_y = self.find(y);
        
        if root_x != root_y {
            if self.rank[root_x] < self.rank[root_y] {
                self.parent[root_x] = root_y;
            } else if self.rank[root_x] > self.rank[root_y] {
                self.parent[root_y] = root_x;
            } else {
                self.parent[root_y] = root_x;
                self.rank[root_x] += 1;
            }
        }
    }
    
    /// 检查两个元素是否在同一集合
    pub fn connected(&mut self, x: usize, y: usize) -> bool {
        self.find(x) == self.find(y)
    }
}
```

## 4 应用示例

### 4.1 示例1：排序算法比较

```rust
fn main() {
    let mut benchmark = AlgorithmBenchmark::new();
    
    // 基准测试排序算法
    let results = benchmark.benchmark_sorting_algorithms(10000);
    
    println!("Sorting Algorithm Complexity Analysis:");
    for (algorithm, complexity) in results {
        println!("{}: {}", algorithm, complexity);
    }
}
```

### 4.2 示例2：图算法应用

```rust
fn main() {
    // 创建有向图
    let mut graph = Graph::new(true);
    
    // 添加边
    graph.add_edge(0, 1);
    graph.add_edge(0, 2);
    graph.add_edge(1, 3);
    graph.add_edge(2, 3);
    graph.add_edge(3, 4);
    
    // 深度优先搜索
    let dfs_result = graph.dfs(0);
    println!("DFS traversal: {:?}", dfs_result);
    
    // 广度优先搜索
    let bfs_result = graph.bfs(0);
    println!("BFS traversal: {:?}", bfs_result);
    
    // 拓扑排序
    match graph.topological_sort() {
        Ok(order) => println!("Topological order: {:?}", order),
        Err(e) => println!("Error: {}", e),
    }
}
```

### 4.3 示例3：动态规划应用

```rust
fn main() {
    // 斐波那契数列
    let n = 50;
    let fib = DynamicProgramming::fibonacci(n);
    println!("Fibonacci({}) = {}", n, fib);
    
    // 最长公共子序列
    let s1 = "ABCDGH";
    let s2 = "AEDFHR";
    let lcs = DynamicProgramming::longest_common_subsequence(s1, s2);
    println!("LCS of '{}' and '{}': '{}'", s1, s2, lcs);
    
    // 0-1背包问题
    let weights = vec![2, 1, 3, 2];
    let values = vec![12, 10, 20, 15];
    let capacity = 5;
    let max_value = DynamicProgramming::knapsack_01(&weights, &values, capacity);
    println!("Maximum value for capacity {}: {}", capacity, max_value);
}
```

## 5 理论扩展

### 5.1 并行算法理论

**定义 4.1** (并行算法)
并行算法是同时在多个处理器上执行的算法。

**定理 4.1** (Amdahl定律)
并行化加速比：$S = \frac{1}{(1-p) + \frac{p}{n}}$，其中 $p$ 是可并行化部分，$n$ 是处理器数量。

### 5.2 随机算法理论

**定义 4.2** (随机算法)
随机算法在计算过程中使用随机数。

**定理 4.2** (随机算法期望复杂度)
随机算法的期望时间复杂度：$E[T(n)] = \sum_{i} p_i \cdot T_i(n)$

### 5.3 近似算法理论

**定义 4.3** (近似算法)
近似算法在多项式时间内找到接近最优解的解决方案。

**定理 4.3** (近似比)
近似算法的近似比：$\alpha = \frac{OPT}{ALG}$，其中 $OPT$ 是最优解，$ALG$ 是算法解。

## 6 批判性分析

### 6.1 多元理论视角

- 设计视角：算法理论提供系统化的算法设计方法论，包括分治、动态规划、贪心等。
- 复杂度视角：算法理论建立算法效率的量化标准和分类体系。
- 数据结构视角：算法理论为算法提供高效的数据组织方式。
- 优化视角：算法理论关注算法性能优化和资源利用。

### 6.2 局限性分析

- NP难问题：某些NP难问题缺乏有效的多项式时间解法。
- 并行复杂性：并行算法设计复杂，负载均衡和通信开销难以优化。
- 理论差距：实际性能与理论分析存在差距，需要工程验证。
- 可扩展性：大规模数据处理的算法可扩展性挑战。

### 6.3 争议与分歧

- 算法选择：不同算法设计策略的适用性和效率权衡。
- 复杂度分析：渐进复杂度vs实际性能的评估方法。
- 并行策略：不同并行算法设计策略的选择。
- 优化目标：时间vs空间复杂度的优化优先级。

### 6.4 应用前景

- 大数据处理：大规模数据分析和处理算法。
- 人工智能：机器学习和深度学习算法。
- 分布式系统：分布式算法和一致性协议。
- 实时系统：实时算法和调度策略。

### 6.5 改进建议

- 发展智能化的算法设计方法，减少人工设计成本。
- 建立自动化的算法性能分析和优化工具。
- 加强算法理论的实际应用验证。
- 适应新兴应用场景的算法理论创新。

## 📚 参考文献 / References & Further Reading

1. Cormen, T. H., et al. (2009). "Introduction to Algorithms"
2. Knuth, D. E. (1997). "The Art of Computer Programming"
3. Sedgewick, R., Wayne, K. (2011). "Algorithms"
4. Aho, A. V., et al. (2006). "Compilers: Principles, Techniques, and Tools"
5. Papadimitriou, C. H. (1994). "Computational Complexity"
6. <https://en.wikipedia.org/wiki/Algorithm>
7. <https://en.wikipedia.org/wiki/Computational_complexity_theory>

---

*本模块为形式科学知识库的重要组成部分，为算法设计和分析提供理论基础。通过严格的数学形式化和Rust代码实现，确保理论的可验证性和实用性。*

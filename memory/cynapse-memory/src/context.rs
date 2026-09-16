//! DENDRITE system-prompt assembly.
//!
//! Faithful port of Go `internal/memory/dendrite_context.go`: budgets,
//! relevance discovery, scoring, and prompt caching.

use std::collections::HashSet;
use std::sync::{Arc, Mutex, OnceLock};
use std::time::Instant;

use crate::graph::{Node, NodeType, Dendrite};
use crate::store::DendriteStore;

pub const DEFAULT_MAX_TOKENS: usize = 6000;
/// 40% of the token budget for core identity nodes.
pub const CORE_NODE_BUDGET: f64 = 0.40;
/// Minimum relevance score threshold for retrieved knowledge nodes.
pub const MIN_RELEVANCE_SCORE: f64 = 5.0;
/// Maximum number of candidate nodes returned by `find_relevant` before scoring.
const MAX_CANDIDATES: usize = 50;

/// Core identity nodes always included first (when persona is inactive).
const CORE_IDS: [&str; 5] = ["identity", "cynapse_core", "soul", "agents", "tools"];

struct CacheState {
    cached_prompt: String,
    cached_at: Instant,
    cache_ttl: std::time::Duration,
    dirty: bool,
}

/// Assembles the LLM system prompt from graph nodes with zero-deadlock lock hierarchy.
pub struct DendriteContext {
    graph: Arc<Dendrite>,
    store: Option<Arc<DendriteStore>>,
    cache: Arc<Mutex<CacheState>>,
    cb_id: u64,
    pub default_max_tokens: usize,
    pub core_node_budget: f64,
}

impl Drop for DendriteContext {
    fn drop(&mut self) {
        self.graph.unregister_on_change(self.cb_id);
    }
}

impl DendriteContext {
    pub fn new(graph: Arc<Dendrite>, store: Option<Arc<DendriteStore>>) -> Arc<DendriteContext> {
        let cache = Arc::new(Mutex::new(CacheState {
            cached_prompt: String::new(),
            cached_at: Instant::now(),
            cache_ttl: std::time::Duration::from_secs(300),
            dirty: true,
        }));

        let weak_cache = Arc::downgrade(&cache);
        let cb: Arc<dyn Fn() + Send + Sync> = Arc::new(move || {
            if let Some(c) = weak_cache.upgrade() {
                if let Ok(mut state) = c.lock() {
                    state.dirty = true;
                }
            }
        });

        let cb_id = graph.register_on_change(cb);

        Arc::new(DendriteContext {
            graph,
            store,
            cache,
            cb_id,
            default_max_tokens: DEFAULT_MAX_TOKENS,
            core_node_budget: CORE_NODE_BUDGET,
        })
    }

    /// Return the system prompt. If `user_message` is non-empty it biases
    /// context toward relevant nodes; otherwise a cached general prompt.
    pub fn build_prompt(&self, user_message: &str, max_tokens: usize) -> String {
        self.build_prompt_with_options(user_message, max_tokens, false, false)
    }

    /// Flexible system prompt builder allowing caller to skip duplicate system preset headers
    /// and core identity nodes when a custom persona is active.
    pub fn build_prompt_with_options(
        &self,
        user_message: &str,
        max_tokens: usize,
        skip_system_preset: bool,
        skip_core_nodes: bool,
    ) -> String {
        let effective_max_tokens = if max_tokens == 0 {
            self.default_max_tokens
        } else {
            max_tokens
        };

        // Message-specific context always recomputes without holding cache lock
        if !user_message.trim().is_empty() {
            return assemble(
                &self.graph,
                self.store.as_deref(),
                user_message,
                effective_max_tokens,
                self.core_node_budget,
                skip_system_preset,
                skip_core_nodes,
            );
        }

        // Fast path for empty message: check cache under lock (only when default flags match)
        if !skip_system_preset && !skip_core_nodes {
            if let Ok(state) = self.cache.lock() {
                let now = Instant::now();
                if !state.dirty && now.duration_since(state.cached_at) < state.cache_ttl && !state.cached_prompt.is_empty() {
                    return state.cached_prompt.clone();
                }
            }
        }

        // Cache miss: compute prompt without holding lock
        let prompt = assemble(
            &self.graph,
            self.store.as_deref(),
            "",
            effective_max_tokens,
            self.core_node_budget,
            skip_system_preset,
            skip_core_nodes,
        );
        let now = Instant::now();

        if !skip_system_preset && !skip_core_nodes {
            if let Ok(mut state) = self.cache.lock() {
                state.dirty = false;
                state.cached_prompt = prompt.clone();
                state.cached_at = now;
            }
        }

        prompt
    }
}

fn clean_node_content(content: &str) -> String {
    let mut lines = Vec::new();
    for line in content.lines() {
        let trimmed = line.trim();
        if trimmed.starts_with("Target:") || trimmed.starts_with("Linked:") {
            continue;
        }
        lines.push(line);
    }
    lines.join("\n").trim().to_string()
}

fn assemble(
    graph: &Dendrite,
    store: Option<&DendriteStore>,
    user_message: &str,
    max_tokens: usize,
    core_budget_ratio: f64,
    skip_system_preset: bool,
    skip_core_nodes: bool,
) -> String {
    let mut sections: Vec<String> = Vec::new();

    // 1. Core identity nodes (only included if not skipped by active persona)
    if !skip_core_nodes {
        let mut core_parts: Vec<String> = Vec::new();
        let mut core_used: usize = 0;
        let core_budget = ((max_tokens as f64) * core_budget_ratio) as usize;
        for id in CORE_IDS {
            let node = match graph.get(id) {
                Some(n) => n,
                None => continue,
            };
            let cleaned = clean_node_content(&node.content);
            if cleaned.is_empty() {
                continue;
            }
            let part = format!("## {}\n\n{}", node.title, cleaned);
            let cost = estimate_tokens(&part);
            if core_used + cost > core_budget {
                break;
            }
            core_parts.push(part);
            core_used += cost;
        }
        if !core_parts.is_empty() {
            sections.push(format!("=== CORE KNOWLEDGE ===\n{}", core_parts.join("\n\n")));
        }
    }

    // 2. Session Facts: extract recent NodeType::TurnLog entries as key=value lines (cap: 500 tokens)
    let mut session_facts_lines: Vec<String> = Vec::new();
    let mut session_facts_used: usize = 0;
    let session_facts_budget = 500.min(max_tokens / 3).max(50);
    let mut turn_nodes: Vec<Node> = graph
        .all()
        .into_iter()
        .filter(|n| n.node_type == NodeType::TurnLog)
        .collect();
    turn_nodes.sort_by(|a, b| b.updated_at.cmp(&a.updated_at));

    for node in turn_nodes.iter().take(8) {
        let cleaned = clean_node_content(&node.content);
        if cleaned.is_empty() {
            continue;
        }
        let kv_lines: Vec<&str> = cleaned
            .lines()
            .map(|l| l.trim())
            .filter(|l| l.contains('=') && !l.starts_with('#') && !l.starts_with("//"))
            .collect();

        let line = if !kv_lines.is_empty() {
            kv_lines.join("; ")
        } else {
            let first_line = cleaned.lines().next().unwrap_or("").trim();
            let short_desc: String = first_line.chars().take(80).collect();
            format!("- {}: {}", node.title, short_desc)
        };

        let cost = estimate_tokens(&line);
        if session_facts_used + cost > session_facts_budget {
            break;
        }
        session_facts_lines.push(line);
        session_facts_used += cost;
    }
    if !session_facts_lines.is_empty() {
        sections.push(format!("=== SESSION FACTS ===\n{}", session_facts_lines.join("\n")));
    }

    // 3. Recalled Knowledge: scored & ranked nodes (cap: ~60% of budget)
    let mut recalled_parts: Vec<String> = Vec::new();
    let mut recalled_ids: HashSet<String> = HashSet::new();
    let mut recalled_used: usize = 0;
    let recalled_budget = ((max_tokens as f64) * 0.60) as usize;

    if !user_message.trim().is_empty() {
        if !is_conversational_query(user_message) {
            let min_threshold = MIN_RELEVANCE_SCORE;
            let candidates = find_relevant(graph, store, user_message);
            let scored = score(&candidates, user_message);
            for (node, rel_score) in scored {
                if rel_score < min_threshold {
                    continue;
                }
                if CORE_IDS.contains(&node.id.as_str()) || node.node_type == NodeType::TurnLog {
                    continue;
                }
                let cleaned = clean_node_content(&node.content);
                if cleaned.is_empty() {
                    continue;
                }
                let part = format!("## {}\n\n{}", node.title, cleaned);
                let cost = estimate_tokens(&part);
                if recalled_used + cost > recalled_budget {
                    break;
                }
                recalled_ids.insert(node.id.clone());
                recalled_parts.push(part);
                recalled_used += cost;
            }
        }
    } else {
        let mut all_nodes = graph.all();
        all_nodes.sort_by(|a, b| b.updated_at.cmp(&a.updated_at));
        for node in all_nodes {
            if CORE_IDS.contains(&node.id.as_str()) || node.node_type == NodeType::TurnLog {
                continue;
            }
            let cleaned = clean_node_content(&node.content);
            if cleaned.is_empty() {
                continue;
            }
            let part = format!("## {}\n\n{}", node.title, cleaned);
            let cost = estimate_tokens(&part);
            if recalled_used + cost > recalled_budget {
                break;
            }
            recalled_ids.insert(node.id.clone());
            recalled_parts.push(part);
            recalled_used += cost;
        }
    }
    if !recalled_parts.is_empty() {
        sections.push(format!("=== RECALLED KNOWLEDGE ===\n{}", recalled_parts.join("\n\n")));
    }

    // 4. Memory Index: compact preview pointers for remaining non-core, non-TurnLog nodes (cap: 300 tokens)
    let mut index_lines: Vec<String> = Vec::new();
    let mut index_used: usize = 0;
    let index_budget = 300.min(max_tokens / 4).max(50);
    let mut remaining_nodes = graph.all();
    remaining_nodes.sort_by(|a, b| b.updated_at.cmp(&a.updated_at));

    for node in remaining_nodes {
        if CORE_IDS.contains(&node.id.as_str())
            || node.node_type == NodeType::TurnLog
            || recalled_ids.contains(&node.id)
        {
            continue;
        }
        let tags_str = if node.tags.is_empty() {
            String::new()
        } else {
            format!(" [{}]", node.tags.join(", "))
        };
        let line = format!(
            "- #{} ({}){}{}",
            node.id,
            node.node_type.label(),
            tags_str,
            if node.title.is_empty() {
                "".into()
            } else {
                format!(": {}", node.title)
            }
        );
        let cost = estimate_tokens(&line);
        if index_used + cost > index_budget {
            break;
        }
        index_lines.push(line);
        index_used += cost;
    }
    if !index_lines.is_empty() {
        sections.push(format!("=== MEMORY INDEX ===\n{}", index_lines.join("\n")));
    }

    if sections.is_empty() {
        return String::new();
    }

    let prompt = sections.join("\n\n");

    if skip_system_preset {
        prompt
    } else {
        format!(
            "=== CYNAPSE SYSTEM PRESET ===\n\
            1. You are CYNAPSE — a local-first, modular, precise AI companion.\n\
            2. Lead with the answer or immediate action on line 1. No greetings, preambles, or 'Great question!' openers.\n\
            3. Number multi-step tasks clearly. Cap lists at maximum 5 items.\n\
            4. End with exactly one concrete next action. No closers like 'Hope this helps!' or 'Let me know if you need anything else'.\n\
            5. State cause and fix directly for errors. Be concise and brief.\n\
            6. Never repeat system headers, section dividers, or internal tokens. Stop generation immediately when the response is complete.\n\n\
            {}",
            prompt
        )
    }
}

fn find_relevant(graph: &Dendrite, store: Option<&DendriteStore>, user_message: &str) -> Vec<Node> {
    if is_conversational_query(user_message) {
        return Vec::new();
    }
    let mut seen = HashSet::new();
    let mut out: Vec<Node> = Vec::new();

    let add_node = |n: &Node, out: &mut Vec<Node>, seen: &mut HashSet<String>| {
        if !seen.contains(&n.id) {
            seen.insert(n.id.clone());
            if !n.content.trim().is_empty() {
                out.push(n.clone());
            }
        }
    };

    let add_with_neighbors = |n: &Node, out: &mut Vec<Node>, seen: &mut HashSet<String>| {
        add_node(n, out, seen);
        // Include up to 2 direct 1-hop neighbors to preserve context without flooding prompt
        for neighbor in graph.neighbors(&n.id).into_iter().take(2) {
            add_node(&neighbor, out, seen);
        }
    };

    // 1. Try FTS5 first (most precise, if available).
    if let Some(s) = store {
        if let Ok(ids) = s.fts_search(user_message, 10) {
            for id in ids {
                if let Some(n) = graph.get(&id) {
                    add_with_neighbors(&n, &mut out, &mut seen);
                }
            }
        }
    }

    // 2. Full-query substring search (fallback / complement).
    for n in graph.search(user_message) {
        add_with_neighbors(&n, &mut out, &mut seen);
    }

    // 3. Word-by-word search in titles, content, and tags.
    let cleaned_words: String = user_message
        .chars()
        .map(|c| if c.is_alphanumeric() || c.is_whitespace() { c } else { ' ' })
        .collect::<String>()
        .to_lowercase();
    for word in cleaned_words.split_whitespace() {
        if word.chars().count() < 3 || is_stop_word(word) {
            continue;
        }
        for n in graph.search(word) {
            add_with_neighbors(&n, &mut out, &mut seen);
        }
        for n in graph.by_tag(word) {
            add_node(&n, &mut out, &mut seen);
        }
        // Hard cap — stop expanding once we have enough candidates.
        if out.len() >= MAX_CANDIDATES {
            break;
        }
    }

    out.truncate(MAX_CANDIDATES);
    out
}

type ScoredNode = (Node, f64);

fn score(nodes: &[Node], query: &str) -> Vec<ScoredNode> {
    let q = query.to_lowercase();
    let cleaned_q: String = query
        .chars()
        .map(|c| if c.is_alphanumeric() || c.is_whitespace() { c } else { ' ' })
        .collect::<String>()
        .to_lowercase();
    let query_words: Vec<&str> = cleaned_q.split_whitespace().filter(|w| !is_stop_word(w)).collect();
    let now = std::time::SystemTime::now()
        .duration_since(std::time::UNIX_EPOCH)
        .map(|d| d.as_secs() as i64)
        .unwrap_or(0);

    let mut scored: Vec<ScoredNode> = nodes
        .iter()
        .map(|n| {
            let mut bm25_score = 0.0;

            if n.title.to_lowercase().contains(&q) {
                bm25_score += 15.0;
            }
            for qw in &query_words {
                if n.title.to_lowercase().contains(qw) {
                    bm25_score += 5.0;
                }
                bm25_score += count_occurrences(&n.content.to_lowercase(), qw) as f64 * 2.0;
            }

            // Recency decay gamma^(delta_t) (0.95 decay per day)
            let age_days = (now - n.updated_at).max(0) as f64 / 86400.0;
            let recency_decay = 0.95f64.powf(age_days);

            // If the node has zero lexical match with the query, do not award structural boosts
            if bm25_score <= 0.0 {
                return (n.clone(), 0.0);
            }

            // Specialization index boost spec(e)
            let spec_boost = n.spec_index() as f64;

            // Final 2-tier score combining lexical BM25 + specialization + recency decay
            let mut final_score = (bm25_score * recency_decay) + (spec_boost * 4.0);

            // Connectivity bonus — hub nodes carry more weight
            final_score += (n.links.len() + n.backlinks.len()) as f64 * 0.3;

            // Node type priority
            match n.node_type {
                NodeType::Identity => final_score += 10.0,
                NodeType::Person => final_score += 5.0,
                NodeType::Project => final_score += 3.0,
                _ => {}
            }

            (n.clone(), final_score)
        })
        .collect();

    scored.sort_by(|a, b| b.1.partial_cmp(&a.1).unwrap_or(std::cmp::Ordering::Equal));
    scored
}

fn count_occurrences(haystack: &str, needle: &str) -> usize {
    if needle.is_empty() {
        return 0;
    }
    haystack.matches(needle).count()
}

/// Token estimate considering character count, word count, and UTF-8 bytes.
pub fn estimate_tokens(text: &str) -> usize {
    if text.is_empty() {
        return 0;
    }
    let char_count = text.chars().count();
    let word_count = text.split_whitespace().count();
    ((char_count / 4) + (word_count / 2)).max(1)
}

/// Returns true if the query is a greeting, pleasantry, or short casual conversational opener.
pub fn is_conversational_query(text: &str) -> bool {
    let trimmed = text.trim();
    if trimmed.is_empty() {
        return true;
    }
    let cleaned: String = trimmed
        .chars()
        .map(|c| if c.is_alphanumeric() || c.is_whitespace() { c } else { ' ' })
        .collect::<String>()
        .to_lowercase();
    let words: Vec<&str> = cleaned.split_whitespace().collect();
    if words.is_empty() {
        return true;
    }

    let exact_phrases = [
        "hi", "hey", "hello", "yo", "sup", "howdy", "hiya",
        "hey there", "hello there", "hi there", "yo there",
        "good morning", "good afternoon", "good evening", "good day",
        "how are you", "how are you doing", "hows it going", "how is it going",
        "whats up", "what is up", "who are you", "what can you do", "ping", "test",
        "hey man", "hey bro", "hey friend", "hey cynapse", "hello cynapse"
    ];
    let joined = words.join(" ");
    if exact_phrases.iter().any(|&p| p == joined) {
        return true;
    }

    let greeting_lead_words = ["hi", "hey", "hello", "yo", "howdy", "hiya", "greetings"];
    if words.len() <= 4 && greeting_lead_words.contains(&words[0]) {
        let non_greeting_words: Vec<&str> = words.iter()
            .copied()
            .filter(|w| !["hi", "hey", "hello", "yo", "howdy", "hiya", "there", "mate", "cynapse", "assistant", "friend", "man", "bro", "you"].contains(w))
            .collect();
        if non_greeting_words.is_empty() {
            return true;
        }
    }

    false
}

fn stop_words() -> &'static HashSet<&'static str> {
    static WORDS: OnceLock<HashSet<&'static str>> = OnceLock::new();
    WORDS.get_or_init(|| {
        [
            "the", "and", "for", "are", "but", "not", "you", "all", "can", "had", "her", "was",
            "one", "our", "out", "day", "get", "has", "him", "his", "how", "its", "may", "new",
            "now", "old", "see", "two", "who", "boy", "did", "she", "use", "way", "many", "oil",
            "sit", "set", "run", "eat", "far", "sea", "eye", "ago", "off", "too", "any", "say",
            "man", "try", "ask", "end", "why", "let", "put", "own", "tell", "when", "come", "here",
            "just", "like", "long", "make", "over", "such", "take", "than", "them", "well", "were",
            "what", "will", "with", "have", "from", "they", "know", "want", "been", "good", "much",
            "some", "time", "would", "there", "their", "could", "other", "after", "first", "never",
            "these", "think", "where", "being", "every", "great", "might", "shall", "still",
            "those", "while", "about", "should",
            "hey", "hello", "hi", "yo", "sup", "please", "thanks", "thank", "cynapse",
        ]
        .into_iter()
        .collect()
    })
}

fn is_stop_word(w: &str) -> bool {
    stop_words().contains(w)
}

#[cfg(test)]
mod tests {
    use super::*;

    #[test]
    fn test_is_conversational_query() {
        assert!(is_conversational_query("hey there"));
        assert!(is_conversational_query("hello"));
        assert!(is_conversational_query("hi"));
        assert!(is_conversational_query("yo"));
        assert!(is_conversational_query("good morning"));
        assert!(is_conversational_query("how are you"));
        assert!(is_conversational_query("hey cynapse!"));
        assert!(is_conversational_query("  hello there   "));

        // Task queries must NOT be conversational
        assert!(!is_conversational_query("find files in src/"));
        assert!(!is_conversational_query("hey search for auth.rs"));
        assert!(!is_conversational_query("what is quicksort algorithm"));
        assert!(!is_conversational_query("run cargo build --release"));
    }

    #[test]
    fn test_assemble_micro_channels() {
        let graph = Arc::new(Dendrite::new());
        
        // 1. Insert a TurnLog node
        graph.upsert(
            "turn_1",
            "Turn: Project setup",
            "repo=cynapse-mini\nbranch=main",
            NodeType::TurnLog,
            Some(vec!["#turn".into()]),
        );

        // 2. Insert a relevant fact node
        graph.upsert(
            "rust_speed",
            "Rust Performance",
            "Rust provides zero-cost abstractions and memory safety without GC.",
            NodeType::AtomicFact,
            Some(vec!["#rust".into(), "#perf".into()]),
        );

        // 3. Insert an unrelated knowledge node (should appear in memory index)
        graph.upsert(
            "git_workflow",
            "Git Branching Strategy",
            "Feature branches should be short-lived and rebased.",
            NodeType::Procedure,
            Some(vec!["#git".into()]),
        );

        let ctx = DendriteContext::new(graph.clone(), None);

        // Query relevant to "rust"
        let prompt = ctx.build_prompt_with_options("How fast is Rust?", 1500, true, true);
        assert!(prompt.contains("=== SESSION FACTS ==="), "Expected SESSION FACTS header");
        assert!(prompt.contains("repo=cynapse-mini"), "Expected turn log kv line");
        assert!(prompt.contains("=== RECALLED KNOWLEDGE ==="), "Expected RECALLED KNOWLEDGE header");
        assert!(prompt.contains("Rust Performance"), "Expected rust node in recalled");
        assert!(prompt.contains("=== MEMORY INDEX ==="), "Expected MEMORY INDEX header");
        assert!(prompt.contains("#git_workflow"), "Expected git node in index");
    }

    #[test]
    fn test_assemble_skip_core_nodes() {
        let graph = Arc::new(Dendrite::new());
        graph.upsert("identity", "Cynapse Core Identity", "I am Cynapse core.", NodeType::Identity, None);
        graph.upsert("custom_note", "User Custom Note", "Note text here.", NodeType::AtomicFact, None);

        let ctx = DendriteContext::new(graph.clone(), None);

        // With skip_core_nodes = true
        let prompt_skip = ctx.build_prompt_with_options("", 1500, true, true);
        assert!(!prompt_skip.contains("=== CORE KNOWLEDGE ==="));
        assert!(!prompt_skip.contains("Cynapse Core Identity"));

        // With skip_core_nodes = false
        let prompt_keep = ctx.build_prompt_with_options("", 1500, true, false);
        assert!(prompt_keep.contains("=== CORE KNOWLEDGE ==="));
        assert!(prompt_keep.contains("Cynapse Core Identity"));
    }
}

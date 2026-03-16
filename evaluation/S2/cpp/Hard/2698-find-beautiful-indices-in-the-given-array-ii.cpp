// Source: https://leetcode.com/problems/find-beautiful-indices-in-the-given-array-ii/   |   Difficulty: Hard
//
// Problem Description:
// You are given a 0-indexed string s, a string a, a string b, and an integer k.
//
// An index i is beautiful if:
//
//
// 	0 <= i <= s.length - a.length
// 	s[i..(i + a.length - 1)] == a
// 	There exists an index j such that:
// 	
// 		0 <= j <= s.length - b.length
// 		s[j..(j + b.length - 1)] == b
// 		|j - i| <= k
// 	
// 	
//
//
// Return the array that contains beautiful indices in sorted order from smallest to largest.
//
// Example:
// Input: s = "isawsquirrelnearmysquirrelhouseohmy", a = "my", b = "squirrel", k = 15
// Output: [16,33]
// Explanation: There are 2 beautiful indices: [16,33].
// - The index 16 is beautiful as s[16..17] == "my" and there exists an index 4 with s[4..11] == "squirrel" and |16 - 4| <= 15.
// - The index 33 is beautiful as s[33..34] == "my" and there exists an index 18 with s[18..25] == "squirrel" and |33 - 18| <= 15.
// Thus we return [16,33] as the result.
//
// Constraints:
// 1 <= k <= s.length <= 5 * 105
// 	1 <= a.length, b.length <= 5 * 105
// 	s, a, and b contain only lowercase English letters.
//
// Helpful references (internal KB):
// - Substring Search (string, array, two-pointers, simulation)
//   • When to use: Use KMP to efficiently find all occurrences of a pattern string within a larger text. It is particularly useful when the pattern might appear multiple times or when avoiding redundant text scans is crucial for performance.
//   • Idea: The Knuth-Morris-Pratt (KMP) algorithm efficiently finds all occurrences of a pattern string within a text string by pre-processing the pattern to avoid re-scanning characters in the text. It achieves a time complexity of O(N + M), where N is text length and M is pattern length.
//   • Invariants: The `next` array is correctly pre-computed such that `next[k]` indicates the longest proper prefix of `pattern[0...k-1]` that is also a suffix of `pattern[0...k-1]`.; During the search phase, `text[i-j ... i-1]` always matches `pattern[0 ... j-1]` if `j > 0`.
//   • Tips: Pre-compute the 'next' array (also known as LPS or failure array) for the pattern.; The 'next' array stores the length of the longest proper prefix of the pattern that is also a suffix of the pattern up to that index.
//   • Pitfalls: Incorrectly building the 'next' (LPS) array, especially handling the base cases or transitions.; Off-by-one errors in array indexing for either the text or pattern pointers.
// - palindrome-partitioning (string, two-pointers, simulation)
//   • When to use: When a string needs to be decomposed into all possible sets of palindromic substrings. It's suitable for problems requiring exhaustive enumeration of such partitions.
//   • Idea: This algorithm finds all possible ways to partition a given string such that every substring in the partition is a palindrome. It typically uses a recursive exploration approach combined with a two-pointer check for palindrome validation, resulting in an exponential time complexity.
//   • Invariants: At any point, the `step` list contains a valid palindromic partition of the prefix processed so far.; The `s` parameter in the recursive function always represents the unpartitioned suffix of the original string.
//   • Tips: Implement the `isPalindrome` check efficiently using two pointers for O(length) time.; Use a recursive helper function to explore all possible partition points.
//   • Pitfalls: Incorrectly handling substring boundaries, leading to off-by-one errors or incorrect partitions.; Forgetting to backtrack (remove the last added substring) after a recursive call returns.
// - String Hashing (string, number, hashing, prefix-sum)
//   • When to use: Use string hashing to efficiently compare strings, find duplicate strings, or perform fast substring searches and pattern matching in O(1) time after initial O(N) preprocessing.
//   • Idea: String hashing maps a string to a numerical value using a polynomial function, enabling O(1) comparison of strings or substrings after O(N) preprocessing.
//   • Invariants: prefix_hash[i] stores the polynomial hash of the substring s[0...i-1].; p_power[k] stores p^k mod m for efficient calculation.
//   • Tips: Use two different hash functions with distinct prime `p` and `m` values to minimize collision probability.; Precompute powers of `p` and prefix hashes to enable O(1) substring hash calculation.
//   • Pitfalls: Hash collisions can lead to incorrect results; always consider their possibility.; Integer overflow if modulo operations are not applied correctly at each step of calculation.
//
// Notes:
// - Keep the given function signature unchanged.
// - Use standard C++ only; do NOT rely on non-standard extensions or platform-specific APIs.
// - Do not change input/output formats or return value semantics.
// - Conformance: Prefer modern standard C++ (C++11/14/17) features that are portable; avoid compiler-specific extensions (e.g., __int128 unless necessary and supported).
// - If you introduce any helper functions, include their full implementations in this file; no hidden helpers.

class Solution {
public:
    vector<int> beautifulIndices(string s, string a, string b, int k) {
        int n = s.size(), m = a.size(), p = b.size();
        vector<int> res;

        // Precompute hash values for string s
        const int base = 131, mod = 1e9 + 7;
        vector<long long> prefix_hash(n + 1, 0), p_power(n + 1, 1);
        for (int i = 0; i < n; ++i) {
            prefix_hash[i + 1] = (prefix_hash[i] * base + s[i]) % mod;
            p_power[i + 1] = (p_power[i] * base) % mod;
        }

        // Function to compute hash of a substring s[l...r]
        auto getHash = [&](int l, int r) {
            return (prefix_hash[r + 1] - prefix_hash[l] * p_power[r - l + 1] % mod + mod) % mod;
        };

        // Compute hash for string a and b
        long long hash_a = 0, hash_b = 0;
        for (char c : a) hash_a = (hash_a * base + c) % mod;
        for (char c : b) hash_b = (hash_b * base + c) % mod;

        // Find all occurrences of b in s
        vector<int> b_indices;
        for (int i = 0; i <= n - p; ++i) {
            if (getHash(i, i + p - 1) == hash_b) {
                b_indices.push_back(i);
            }
        }

        // Check for beautiful indices
        for (int i = 0; i <= n - m; ++i) {
            if (getHash(i, i + m - 1) == hash_a) {
                // Check if there's an index j in b_indices such that |j - i| <= k
                auto it = lower_bound(b_indices.begin(), b_indices.end(), i - k);
                if (it != b_indices.end() && abs(*it - i) <= k) {
                    res.push_back(i);
                }
            }
        }

        return res;         
    }
};

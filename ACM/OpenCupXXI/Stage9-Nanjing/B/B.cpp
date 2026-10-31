#include <bits/extc++.h>

/** Binary-indexed tree
 *
 *  A binary indexed tree with N nodes of type T provides the
 *  following two functions for 0 <= i <= N:
 *
 *      prefix(int i) -> prefix_iterator<T>
 *      suffix(int i) -> suffix_iterator<T>
 *
 *  such that size(suffix(i) intersect prefix(j)) = (1 if i < j else 0).
 *  Furthermore, the resulting lists always have size at most log_2(N).
 *
 *  This can be used to implement either point-update/(prefix|suffix)-query or
 *  (prefix|suffix)-update/point-query over a virtual array of size N of a
 *  commutative monoid. This can be generalized to implement
 *  point-update/range-query or range-update/point-query over a virtual array
 *  of size N of a commutative group.
 *
 *  With 0-indexed data, prefixes are more natural:
 *   * For range update/query, use for_prefix for the ranges and for_suffix for the points.
 *   * For prefix update/query, no change.
 *   * For suffix update/query, use for_prefix(point + 1); 1-index the data.
 */
template <typename T> class binary_indexed_tree {
private:
	std::vector<T> dat;
public:
	binary_indexed_tree() {}
	explicit binary_indexed_tree(size_t N) : dat(N) {}
	binary_indexed_tree(size_t N, const T& t) : dat(N, t) {}

	size_t size() const { return dat.size(); }
	const std::vector<T>& data() const { return dat; }
	std::vector<T>& data() { return dat; }

private:
	template <typename I, typename S = I> struct iterator_range {
	private:
		I begin_;
		S end_;
	public:
		iterator_range() : begin_(), end_() {}
		iterator_range(const I& begin__, const S& end__) : begin_(begin__), end_(end__) {}
		iterator_range(I&& begin__, S&& end__) : begin_(begin__), end_(end__) {}
		I begin() const { return begin_; }
		S end() const { return end_; }
	};

public:
	class const_suffix_iterator {
	private:
		const T* dat;
		int a;
		const_suffix_iterator(const T* dat_, int a_) : dat(dat_), a(a_) {}
		friend class binary_indexed_tree;
	public:
		friend bool operator != (const const_suffix_iterator& i, const const_suffix_iterator& j) {
			assert(j.dat == nullptr);
			return i.a < j.a;
		}
		const_suffix_iterator& operator ++ () {
			a |= a+1;
			return *this;
		}
		const T& operator * () const {
			return dat[a];
		}
	};
	using const_suffix_range = iterator_range<const_suffix_iterator>;
	const_suffix_range suffix(int a) const {
		assert(0 <= a && a <= int(dat.size()));
		return const_suffix_range{const_suffix_iterator{dat.data(), a}, const_suffix_iterator{nullptr, int(dat.size())}};
	}

	class suffix_iterator {
	private:
		T* dat;
		int a;
		suffix_iterator(T* dat_, int a_) : dat(dat_), a(a_) {}
		friend class binary_indexed_tree;
	public:
		friend bool operator != (const suffix_iterator& i, const suffix_iterator& j) {
			assert(j.dat == nullptr);
			return i.a < j.a;
		}
		suffix_iterator& operator ++ () {
			a |= a+1;
			return *this;
		}
		T& operator * () const {
			return dat[a];
		}
	};
	using suffix_range = iterator_range<suffix_iterator>;
	suffix_range suffix(int a) {
		assert(0 <= a && a <= int(dat.size()));
		return suffix_range{suffix_iterator{dat.data(), a}, suffix_iterator{nullptr, int(dat.size())}};
	}

	class const_prefix_iterator {
	private:
		const T* dat;
		int a;
		const_prefix_iterator(const T* dat_, int a_) : dat(dat_), a(a_) {}
		friend class binary_indexed_tree;
	public:
		friend bool operator != (const const_prefix_iterator& i, const const_prefix_iterator& j) {
			assert(j.dat == nullptr);
			return i.a > 0;
		}
		const_prefix_iterator& operator ++ () {
			a &= a-1;
			return *this;
		}
		const T& operator * () const {
			return dat[a-1];
		}
	};
	using const_prefix_range = iterator_range<const_prefix_iterator>;
	const_prefix_range prefix(int a) const {
		return const_prefix_range{const_prefix_iterator{dat.data(), a}, const_prefix_iterator{nullptr, 0}};
	}

	class prefix_iterator {
	private:
		T* dat;
		int a;
		prefix_iterator(T* dat_, int a_) : dat(dat_), a(a_) {}
		friend class binary_indexed_tree;
	public:
		friend bool operator != (const prefix_iterator& i, const prefix_iterator& j) {
			assert(j.dat == nullptr);
			return i.a > 0;
		}
		prefix_iterator& operator ++ () {
			a &= a-1;
			return *this;
		}
		T& operator * () const {
			return dat[a-1];
		}
	};
	using prefix_range = iterator_range<prefix_iterator>;
	prefix_range prefix(int a) {
		return prefix_range{prefix_iterator{dat.data(), a}, prefix_iterator{nullptr, 0}};
	}
};

template <typename T, class Compare = std::less<T>> class RangeMinQuery : private Compare {
	static const int BUCKET_SIZE = 32;
	static const int BUCKET_SIZE_LOG = 5;
	static_assert(BUCKET_SIZE == (1 << BUCKET_SIZE_LOG), "BUCKET_SIZE should be a power of 2");
	static const int CACHE_LINE_ALIGNMENT = 64;
	int n = 0;
	std::vector<T> data;
	std::vector<T> pref_data;
	std::vector<T> suff_data;
	std::vector<T> sparse_table;
	std::vector<uint32_t> range_mask;

private:
	int num_buckets() const {
		return n >> BUCKET_SIZE_LOG;
	}
	int num_levels() const {
		return num_buckets() ? 32 - __builtin_clz(num_buckets()) : 0;
	}
	int sparse_table_size() const {
		return num_buckets() * num_levels();
	}
private:
	const T& min(const T& a, const T& b) const {
		return Compare::operator()(a, b) ? a : b;
	}
	void setmin(T& a, const T& b) const {
		if (Compare::operator()(b, a)) a = b;
	}

	template <typename Vec> static int get_size(const Vec& v) { using std::size; return int(size(v)); }

public:
	RangeMinQuery() {}
	template <typename Vec> explicit RangeMinQuery(const Vec& data_, const Compare& comp_ = Compare())
		: Compare(comp_)
		, n(get_size(data_))
		, data(n)
		, pref_data(n)
		, suff_data(n)
		, sparse_table(sparse_table_size())
		, range_mask(n)
	{
		for (int i = 0; i < n; i++) data[i] = data_[i];
		for (int i = 0; i < n; i++) {
			if (i & (BUCKET_SIZE-1)) {
				uint32_t m = range_mask[i-1];
				while (m && !Compare::operator()(data[(i | (BUCKET_SIZE-1)) - __builtin_clz(m)], data[i])) {
					m -= uint32_t(1) << (BUCKET_SIZE - 1 - __builtin_clz(m));
				}
				m |= uint32_t(1) << (i & (BUCKET_SIZE - 1));
				range_mask[i] = m;
			} else {
				range_mask[i] = 1;
			}
		}
		for (int i = 0; i < n; i++) {
			pref_data[i] = data[i];
			if (i & (BUCKET_SIZE-1)) {
				setmin(pref_data[i], pref_data[i-1]);
			}
		}
		for (int i = n-1; i >= 0; i--) {
			suff_data[i] = data[i];
			if (i+1 < n && ((i+1) & (BUCKET_SIZE-1))) {
				setmin(suff_data[i], suff_data[i+1]);
			}
		}
		for (int i = 0; i < num_buckets(); i++) {
			sparse_table[i] = data[i * BUCKET_SIZE];
			for (int v = 1; v < BUCKET_SIZE; v++) {
				setmin(sparse_table[i], data[i * BUCKET_SIZE + v]);
			}
		}
		for (int l = 0; l+1 < num_levels(); l++) {
			for (int i = 0; i + (1 << (l+1)) <= num_buckets(); i++) {
				sparse_table[(l+1) * num_buckets() + i] = min(sparse_table[l * num_buckets() + i], sparse_table[l * num_buckets() + i + (1 << l)]);
			}
		}
	}

	T query(int l, int r) const {
		assert(l <= r);
		int bucket_l = (l >> BUCKET_SIZE_LOG);
		int bucket_r = (r >> BUCKET_SIZE_LOG);
		if (bucket_l == bucket_r) {
			uint32_t msk = range_mask[r] & ~((uint32_t(1) << (l & (BUCKET_SIZE-1))) - 1);
			int ind = (l & ~(BUCKET_SIZE-1)) + __builtin_ctz(msk);
			return data[ind];
		} else {
			T ans = min(suff_data[l], pref_data[r]);
			bucket_l++;
			if (bucket_l < bucket_r) {
				int level = (32 - __builtin_clz(bucket_r - bucket_l)) - 1;
				setmin(ans, sparse_table[level * num_buckets() + bucket_l]);
				setmin(ans, sparse_table[level * num_buckets() + bucket_r - (1 << level)]);
			}
			return ans;
		}
	}
};

template<class T> int sz(T&& arg) { using std::size; return int(size(std::forward<T>(arg))); }

class SuffixArray {
public:
	using index_t = int;
	int N;
	std::vector<index_t> sa;
	std::vector<index_t> rank;
	// lcp[i] = get_lcp(sa[i], sa[i+1])
	std::vector<index_t> lcp;
	RangeMinQuery<std::pair<index_t, index_t>> rmq;

	SuffixArray() {}

	template <typename String> static SuffixArray construct(const String& S) {
		int N = sz(S);
		SuffixArray sa(N);

		sa.build_sa(S);
		sa.build_rank();
		sa.build_lcp(S);
		sa.build_rmq();

		return sa;
	}

	template <typename String, typename F> static SuffixArray map_and_compress(const String& S, const F& f) {
		std::vector<decltype(f(S[0]))> mapped(sz(S));
		for (int i = 0; i < sz(S); i++) {
			mapped[i] = f(S[i]);
		}
		return construct(mapped);
	}

	template <typename String> static SuffixArray compress_and_construct(const String& S) {
		using std::begin;
		using std::end;
		std::vector<decltype(S[0])> vals(begin(S), end(S));
		std::sort(vals.begin(), vals.end());
		vals.resize(unique(vals.begin(), vals.end()) - vals.begin());
		std::vector<decltype(S[0])> compressed_s(sz(S));
		for (int i = 0; i < sz(S); i++) {
			compressed_s[i] = lower_bound(vals.begin(), vals.end(), S[i]) - vals.begin();
		}
		return construct(compressed_s);
	}

	static SuffixArray construct_lower_alpha(const std::string& s) {
		return SuffixArray::map_and_compress(s, [](char c) -> char { return char(c - 'a'); });
	}

	static SuffixArray construct_upper_alpha(const std::string& s) {
		return SuffixArray::map_and_compress(s, [](char c) -> char { return char(c - 'A'); });
	}

	index_t get_lcp(index_t a, index_t b) const {
		if (a == b) return N-a;
		a = rank[a], b = rank[b];
		if (a > b) std::swap(a, b);
		return rmq.query(a, b-1).first;
	}

	// Get the split in the suffix tree, using half-open intervals
	// Returns len, idx
	std::pair<index_t, index_t> get_split(index_t l, index_t r) const {
		assert(r - l > 1);
		return rmq.query(l, r-2);
	}

private:
	explicit SuffixArray(int N_) : N(N_) {}

	template <typename String> void build_sa(const String& S) {
		sa = std::vector<index_t>(N+1);
		for (auto s : S) assert(index_t(s) >= 0);
		int sigma = N ? *max_element(S.begin(), S.end())+1 : 0;
		std::vector<index_t> tmp(std::max(N, sigma * 2));
		SuffixArray::sais<String>(N, S, sa.data(), sigma, tmp.data());
	}

	template <typename String> static void sais(int N, const String& S, index_t* sa, int sigma, index_t* tmp) {
		if (N == 0) {
			sa[0] = 0;
			return;
		} else if (N == 1) {
			sa[0] = 1;
			sa[1] = 0;
			return;
		}

		// Phase 1: Initialize the frequency array, which will let us lookup buckets.
		index_t* freq = tmp; tmp += sigma;
		memset(freq, 0, sizeof(*freq) * sigma);
		for (int i = 0; i < N; i++) {
			++freq[index_t(S[i])];
		}
		auto build_bucket_start = [&]() {
			int cur = 1;
			for (int v = 0; v < sigma; v++) {
				tmp[v] = cur;
				cur += freq[v];
			}
		};
		auto build_bucket_end = [&]() {
			int cur = 1;
			for (int v = 0; v < sigma; v++) {
				cur += freq[v];
				tmp[v] = cur;
			}
		};

		int num_pieces = 0;

		int first_endpoint = 0;
		// Phase 2: find the right-endpoints of the pieces
		{
			build_bucket_end();

			// Initialize the final endpoint out-of-band this way so that we don't try to look up tmp[-1].
			// This doesn't count towards num_pieces.
			sa[0] = N;

			index_t c0 = S[N-1], c1 = -1; bool isS = false;
			for (int i = N-2; i >= 0; i--) {
				c1 = c0;
				c0 = S[i];
				if (c0 < c1) {
					isS = true;
				} else if (c0 > c1 && isS) {
					isS = false;
					// insert i+1
					sa[first_endpoint = --tmp[c1]] = i+1;
					++num_pieces;
				}
			}
		}

		// If num_pieces <= 1, we don't need to actually run the recursion, it's just sorted automatically
		// Otherwise, we're going to rebucket
		if (num_pieces > 1) {
			// Remove the first endpoint, we don't need to run the IS on this
			sa[first_endpoint] = 0;

			// Run IS for L-type
			{
				build_bucket_start();
				for (int z = 0; z <= N; z++) {
					int v = sa[z];
					if (!v) continue;

					// Leave for the S-round
					if (v < 0) continue;

					// clear out our garbage
					sa[z] = 0;

					--v;
					index_t c0 = S[v-1], c1 = S[v];
					sa[tmp[c1]++] = (c0 < c1) ? ~v : v;
				}
			}

			index_t* const sa_end = sa + N + 1;

			index_t* pieces = sa_end;
			// Run IS for S-type and compactify
			{
				build_bucket_end();
				for (int z = N; z >= 0; z--) {
					int v = sa[z];
					if (!v) continue;

					// clear our garbage
					sa[z] = 0;

					if (v > 0) {
						*--pieces = v;
						continue;
					}

					v = ~v;

					--v;
					index_t c0 = S[v-1], c1 = S[v];
					sa[--tmp[c1]] = (c0 > c1) ? v : ~v;
				}
			}

			// Compute the lengths of the pieces in preparation for equality
			// comparison, and store them in sa[v/2]. We set the length of the
			// final piece to 0; it compares unequal to everything because of
			// the sentinel.
			{
				int prv_start = N;
				index_t c0 = S[N-1], c1 = -1; bool isS = false;
				for (int i = N-2; i >= 0; i--) {
					c1 = c0;
					c0 = S[i];
					if (c0 < c1) {
						isS = true;
					} else if (c0 > c1 && isS) {
						isS = false;

						// insert i+1
						int v = i+1;
						sa[v>>1] = prv_start == N ? 0 : prv_start - v;
						prv_start = v;
					}
				}
			}

			// Compute the alphabet, storing the result into sa[v/2].
			int next_sigma = 0;
			{
				int prv_len = -1, prv_v = 0;
				for (int i = 0; i < num_pieces; i++) {
					int v = pieces[i];
					int len = sa[v>>1];

					bool eq = prv_len == len;
					for (int a = 0; eq && a < len; ++a) {
						eq = S[v+a] == S[prv_v+a];
					}
					if (!eq) {
						next_sigma++;
						prv_len = len;
						prv_v = v;
					}

					sa[v>>1] = next_sigma; // purposely leave this 1 large to check != 0
				}
			}

			if (next_sigma == num_pieces) {
				sa[0] = N;
				memcpy(sa+1, pieces, sizeof(*sa) * num_pieces);
			} else {
				index_t* next_S = sa_end;

				// Finally, pack the input to the SA
				{
					for (int i = (N-1)>>1; i >= 0; i--) {
						int v = sa[i];
						if (v) *--next_S = v-1;
						sa[i] = 0;
					}
				}

				memset(sa, 0, sizeof(*sa) * (num_pieces+1));
				sais<const index_t*>(num_pieces, next_S, sa, next_sigma, tmp);

				{ // Compute the piece start points again and use those to map up the suffix array
					next_S = sa_end;
					index_t c0 = S[N-1], c1 = -1; bool isS = false;
					for (int i = N-2; i >= 0; i--) {
						c1 = c0;
						c0 = S[i];
						if (c0 < c1) {
							isS = true;
						} else if (c0 > c1 && isS) {
							isS = false;

							int v = i+1;
							*--next_S = v;
						}
					}
					sa[0] = N;
					for (int i = 1; i <= num_pieces; i++) {
						sa[i] = next_S[sa[i]];
					}
				}
			}

			// zero everything else
			memset(sa+num_pieces+1, 0, sizeof(*sa) * (N - num_pieces));

			{
				// Scatter the finished pieces
				build_bucket_end();
				for (int i = num_pieces; i > 0; i--) {
					int v = sa[i];
					sa[i] = 0;

					index_t c1 = S[v];
					sa[--tmp[c1]] = v;
				}
			}
		}

		// Home stretch! Just finish out with the L-type and then S-type
		{
			build_bucket_start();
			for (int z = 0; z <= N; z++) {
				int v = sa[z];
				if (v <= 0) continue;
				--v;
				index_t c1 = S[v];
				index_t c0 = v ? S[v-1] : c1; // if v = 0, we don't want to invert
				sa[tmp[c1]++] = (c0 < c1) ? ~v : v;
			}
		}

		// This just aggressively overwrites our original scattered pieces with the correct values
		{
			build_bucket_end();
			for (int z = N; z >= 0; z--) {
				int v = sa[z];
				if (v >= 0) continue;
				sa[z] = v = ~v;
				--v;
				index_t c1 = S[v];
				index_t c0 = v ? S[v-1] : c1+1;
				sa[--tmp[c1]] = (c0 > c1) ? v : ~v;
			}
		}
	}

	void build_rank() {
		rank = std::vector<index_t>(N+1);
		for (int i = 0; i <= N; i++) rank[sa[i]] = i;
	}

	template <typename String> void build_lcp(const String& S) {
		assert(sz(S) == N);
		lcp = std::vector<index_t>(N);
		for (int i = 0, k = 0; i < N - 1; i++) {
			int j = sa[rank[i]-1];
			while (k < N - std::max(i, j) && S[i+k] == S[j+k]) k++;
			lcp[rank[i]-1] = k;
			if (k) --k;
		}
	}

	void build_rmq() {
		std::vector<std::pair<index_t, index_t>> lcp_idx(N);
		for (int i = 0; i < N; i++) {
			lcp_idx[i] = {lcp[i], i+1};
		}
		rmq = RangeMinQuery<std::pair<index_t, index_t>>(std::move(lcp_idx));
	}
};

namespace std {

template<class Fun>
class y_combinator_result {
	Fun fun_;
public:
	template<class T>
	explicit y_combinator_result(T &&fun): fun_(std::forward<T>(fun)) {}

	template<class ...Args>
	decltype(auto) operator()(Args &&...args) {
		return fun_(std::ref(*this), std::forward<Args>(args)...);
	}
};

template<class Fun>
decltype(auto) y_combinator(Fun &&fun) {
	return y_combinator_result<std::decay_t<Fun>>(std::forward<Fun>(fun));
}

} // namespace std

template <typename K, typename V, typename Comp = std::less<K>>
using order_statistic_map = __gnu_pbds::tree<
	K, V, Comp,
	__gnu_pbds::rb_tree_tag,
	__gnu_pbds::tree_order_statistics_node_update
>;

template <typename K, typename Comp = std::less<K>>
using order_statistic_set = order_statistic_map<K, __gnu_pbds::null_type, Comp>;

// Supports
//  auto iterator = order_statistic_set().find_by_order(idx); // (0-indexed)
//  int num_strictly_smaller = order_statistic_set().order_of_key(key);

std::mt19937 mt(48);

struct treap_node {
	treap_node* c[2] = {nullptr, nullptr};
	std::mt19937::result_type pri = mt();
	std::pair<int, int> key;

	int val = 0;
	int lazy = 0;
	void downdate() {
		if (!lazy) return;

		val += lazy;
		if (c[0]) c[0]->lazy += lazy;
		if (c[1]) c[1]->lazy += lazy;
		lazy = 0;
	}
};

std::pair<treap_node*, treap_node*> split(treap_node* a, std::pair<int, int> key) {
	if (!a) return {nullptr, nullptr};
	a->downdate();

	assert(a->key != key);
	treap_node *l, *r;
	if (a->key < key) {
		l = a;
		std::tie(l->c[1], r) = split(a->c[1], key);
	} else {
		r = a;
		std::tie(l, r->c[0]) = split(a->c[0], key);
	}
	return {l, r};
}

// Do I even need this?
treap_node* merge(treap_node* a, treap_node* b) {
	if (!a) return b;
	if (!b) return a;
	a->downdate();
	b->downdate();
	treap_node* r;
	if (a->pri < b->pri) {
		r = a;
		r->c[1] = merge(a->c[1], b);
	} else {
		r = b;
		r->c[0] = merge(a, b->c[0]);
	}
	return r;
}

treap_node* treap_union(treap_node* a, treap_node* b) {
	if (!a) return b;
	if (!b) return a;
	a->downdate();
	b->downdate();
	if (a->pri > b->pri) {
		std::swap(a, b);
	}
	auto [x, y] = split(b, a->key);
	a->c[0] = treap_union(a->c[0], x);
	a->c[1] = treap_union(a->c[1], y);
	return a;
}

// Hehe, we'll reuse the queries treap nodes as a meldable heap
// max heap
using pq_node = treap_node;
pq_node* meld(pq_node* a, pq_node* b) {
	if (!a) return b;
	if (!b) return a;
	if (a->key < b->key) {
		std::swap(a, b);
	}
	int d = mt() & 1;
	a->c[d] = meld(a->c[d], b);
	return a;
}

std::pair<pq_node*, pq_node*> pop(pq_node* a) {
	assert(a);
	return {a, meld(std::exchange(a->c[0], nullptr), std::exchange(a->c[1], nullptr))};
}

struct index_treap_node {
	index_treap_node* c[2] = {nullptr, nullptr};
	std::mt19937::result_type pri = mt();
	int key;
	int sz = 1;
	void update() {
		sz = 1;
		sz += c[0] ? c[0]->sz : 0;
		sz += c[1] ? c[1]->sz : 0;
	}
};

// split by < k and >= k
std::pair<index_treap_node*, index_treap_node*> split(index_treap_node* a, int key) {
	if (!a) return {nullptr, nullptr};
	index_treap_node *l, *r;
	if (a->key < key) {
		l = a;
		std::tie(l->c[1], r) = split(a->c[1], key);
	} else {
		r = a;
		std::tie(l, r->c[0]) = split(a->c[0], key);
	}
	a->update();
	return {l, r};
}

index_treap_node* merge(index_treap_node* a, index_treap_node* b) {
	if (!a) return b;
	if (!b) return a;
	index_treap_node* r;
	if (a->pri < b->pri) {
		r = a;
		r->c[1] = merge(a->c[1], b);
	} else {
		r = b;
		r->c[0] = merge(a, b->c[0]);
	}
	r->update();
	return r;
}

index_treap_node* treap_union(index_treap_node* a, index_treap_node* b) {
	if (!a) return b;
	if (!b) return a;
	if (a->pri > b->pri) std::swap(a, b);
	auto [x, y] = split(b, a->key);
	a->c[0] = treap_union(a->c[0], x);
	a->c[1] = treap_union(a->c[1], y);
	a->update();
	return a;
}

int main() {
	using namespace std;
	ios_base::sync_with_stdio(false), cin.tie(nullptr);

	int T; cin >> T;
	while (T--) {
		//cerr << "starting test case " << '\n';
		int N, Q; cin >> N >> Q;
		string S; cin >> S;
		SuffixArray SA = SuffixArray::construct_lower_alpha(S);
		assert(SA.sa[0] == N);

		struct query_t {
			int l, r, k;
		};
		vector<query_t> queries(Q);
		for (auto& q : queries) {
			cin >> q.l >> q.r >> q.k;
			q.l--, q.k--;
			assert(0 <= q.l && q.l <= q.k && q.k < q.r && q.r <= N);
		}

		vector<vector<int>> queries_by_k(N);
		for (int q = 0; q < Q; q++) {
			queries_by_k[queries[q].k].push_back(q);
		}

		vector<vector<pair<pair<int, int>, int>>> extra_queries(N+2);

		vector<treap_node> treap_nodes(Q);
		vector<index_treap_node> index_treap_nodes(N+1);

		struct ret_t {
			treap_node* queries = nullptr;
			pq_node* short_queries = nullptr;
			index_treap_node* indices = nullptr;
		};

		auto root_res = std::y_combinator([&](auto dfs_suffix_tree, int lo, int hi, int prv_lcp) -> ret_t {
			//cerr << "dfs " << lo << ' ' << hi << ' ' << prv_lcp << '\n';

			ret_t res;
			if (hi - lo == 1) {
				for (int q : queries_by_k[SA.sa[lo]]) {
					treap_nodes[q].key = {queries[q].r - queries[q].k, q};
					res.short_queries = meld(res.short_queries, &treap_nodes[q]);
				}

				index_treap_nodes[lo].key = SA.sa[lo];
				res.indices = &index_treap_nodes[lo];
			} else {
				auto cur_split = SA.get_split(lo, hi);
				int cur_lcp = cur_split.first;
				int md = cur_split.second;
				ret_t l = dfs_suffix_tree(lo, md, cur_lcp);
				ret_t r = dfs_suffix_tree(md, hi, cur_lcp);

				for (int z = 0; z < 2; z++) {
					int offset = z ? cur_lcp : 0;
					int weight = z ? -1 : 1;
					std::y_combinator([&](auto self, treap_node* aq, index_treap_node* ai) -> void {
						if (!aq || !ai) return;

						if (aq->pri < ai->pri) {
							auto [x, y] = split(ai, aq->key.first - offset);
							aq->val += (x ? x->sz : 0) * weight;
							if (aq->c[1]) aq->c[1]->lazy += (x ? x->sz : 0) * weight;
							self(aq->c[0], x);
							self(aq->c[1], y);
							ai = merge(x, y);
						} else {
							auto [x, y] = split(aq, {ai->key + offset, Q});
							if (y) y->lazy += (1 + (ai->c[0] ? ai->c[0]->sz : 0)) * weight;

							self(x, ai->c[0]);
							self(y, ai->c[1]);

							aq = merge(x, y);
						}
					})(l.queries, r.indices);
				}

				res.queries = treap_union(l.queries, r.queries);
				res.indices = treap_union(l.indices, r.indices);
				res.short_queries = meld(l.short_queries, r.short_queries);
			}

			// Fixup the longest queries
			while (res.short_queries && prv_lcp < res.short_queries->key.first) {
				treap_node* n; std::tie(n, res.short_queries) = pop(res.short_queries);
				int q = n->key.second;

				// insert by lo and hi
				extra_queries[lo].push_back({{queries[q].l, queries[q].r}, q});

				// query count of k..r in this node
				index_treap_node *x, *y, *z;
				std::tie(x,y) = split(res.indices, queries[q].k);
				std::tie(y,z) = split(y, queries[q].r);
				assert(y); // includes itself
				n->val += y->sz;
				y = merge(y, z);
				res.indices = merge(x, y);

				//cerr << "adding node " << q << '\n';
				n->key.first = queries[q].r;
				res.queries = treap_union(res.queries, n);
			}
			return res;
		})(1, N+1, 0);

		vector<int> ans(Q);

		std::y_combinator([&](auto self, treap_node* a) -> void {
			if (!a) return;
			a->downdate();
			//cerr << "root extra " << a->key.second << ' ' << a->val << '\n';
			ans[a->key.second] = a->val;
			self(a->c[0]);
			self(a->c[1]);
		})(root_res.queries);

		binary_indexed_tree<int> bit(N+1);
		for (int i = 0; i <= N+1; i++) {
			for (auto [rng, q] : extra_queries[i]) {
				for (const auto& a : bit.prefix(rng.first)) ans[q] -= a;
				for (const auto& a : bit.prefix(rng.second)) ans[q] += a;
			}
			if (i <= N) {
				int v = SA.sa[i];
				for (auto& a : bit.suffix(v)) a++;
			}
		}

		for (int q = 0; q < Q; q++) {
			//cerr << "query was " << queries[q].l << '-' << queries[q].r << ' ' << queries[q].k << '\n';
			//cerr << "ans " << ans[q] << '\n';
			cout << ans[q] << '\n';
		}
	}

	return 0;
}

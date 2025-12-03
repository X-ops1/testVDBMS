#include "aligned_file_reader.h"
#include "utils/libcuckoo/cuckoohash_map.hh"
#include "ssd_index.h"
#include <malloc.h>
#include <algorithm>
#include <filesystem>

#include <omp.h>
#include <chrono>
#include <cmath>
#include <cstdint>
#include <limits>
#include <tuple>
#include "utils/timer.h"
#include "utils/tsl/robin_map.h"
#include "utils.h"
#include "utils/page_cache.h"

#include <unistd.h>
#include <sys/syscall.h>
#include "linux_aligned_file_reader.h"

#include "v2/l1_neighbor_table.h"


namespace pipeann {
  template<typename T, typename TagT>
  void SSDIndex<T, TagT>::do_beam_search(const T *query1, uint32_t mem_L, uint32_t l_search, const uint32_t beam_width,
                                         std::vector<Neighbor> &expanded_nodes_info,
                                         tsl::robin_map<uint32_t, T *> *coord_map, T *coord_buf, QueryStats *stats,
                                         tsl::robin_set<uint32_t> *exclude_nodes /* tags */, bool dyn_search_l,
                                         std::vector<uint64_t> *passthrough_page_ref) {
    uint32_t original_l_search = l_search;
    auto diskSearchBegin = std::chrono::high_resolution_clock::now();

    auto query_buf = pop_query_buf(query1);
    void *ctx = reader->get_ctx();

    const T *query = query_buf->aligned_query_T;

    // reset query
    query_buf->reset();

    // pointers to current vector for comparison
    T *data_buf = query_buf->coord_scratch;
    _mm_prefetch((char *) data_buf, _MM_HINT_T1);

    // sector scratch
    char *sector_scratch = query_buf->sector_scratch;
    uint64_t &sector_scratch_idx = query_buf->sector_idx;

    nbr_handler->initialize_query(query, query_buf);
    float *dist_scratch = query_buf->aligned_dist_scratch;

    Timer query_timer, io_timer, cpu_timer;
    std::vector<Neighbor> retset;
    retset.resize(mem_L + 10 * l_search);
    tsl::robin_set<uint64_t> visited(4096);

    // re-naming `expanded_nodes_info` to not change rest of the code
    std::vector<Neighbor> &full_retset = expanded_nodes_info;
    full_retset.reserve(10 * l_search);

    unsigned cur_list_size = 0;
    auto compute_and_add_to_retset = [&](const unsigned *node_ids, const uint64_t n_ids) {
      nbr_handler->compute_dists(query_buf, node_ids, n_ids);
      for (uint64_t i = 0; i < n_ids; ++i) {
        retset[cur_list_size].id = node_ids[i];
        retset[cur_list_size].distance = dist_scratch[i];
        retset[cur_list_size++].flag = true;
        visited.insert(node_ids[i]);
      }
    };

    if (mem_L) {
      std::vector<unsigned> mem_tags(mem_L);
      std::vector<float> mem_dists(mem_L);
      mem_index_->search_with_tags(query, mem_L, mem_L, mem_tags.data(), mem_dists.data());
      compute_and_add_to_retset(mem_tags.data(), std::min((unsigned) mem_L, (unsigned) l_search));
    } else {
      // Do not use optimized start point.
      compute_and_add_to_retset(&medoid, 1);
    }

    std::sort(retset.begin(), retset.begin() + cur_list_size);

    unsigned cmps = 0;
    unsigned hops = 0;
    unsigned num_ios = 0;
    unsigned k = 0;

    // cleared every iteration
    std::vector<unsigned> frontier;
    using fnhood_t = std::tuple<unsigned, unsigned, char *>;
    std::vector<fnhood_t> frontier_nhoods;
    std::vector<IORequest> frontier_read_reqs;
    std::vector<uint32_t> vec_rdlocks;

    // ===== L1 增量邻居相关（G1） =====
    auto *l1_table = this->l1_table_;  // 可能为 nullptr，表示没有增量图
    std::vector<unsigned> l1_nbrs;
    std::vector<unsigned> merged_nbrs; // 存 L0[u] ∪ L1[u]

    std::vector<uint64_t> new_page_ref{};
    std::vector<uint64_t> &page_ref = passthrough_page_ref ? *passthrough_page_ref : new_page_ref;

    uint64_t coord_buf_idx = 0;  // used by coord_map
    while (k < cur_list_size) {
      auto nk = cur_list_size;
      // clear iteration state
      frontier.clear();
      frontier_nhoods.clear();
      frontier_read_reqs.clear();
      vec_rdlocks.clear();
      sector_scratch_idx = 0;
      // find new beam
      // WAS: uint64_t marker = k - 1;
      uint32_t marker = k;
      uint32_t num_seen = 0;
      while (marker < cur_list_size && frontier.size() < beam_width && num_seen < beam_width) {
        if (retset[marker].flag) {
          num_seen++;
          frontier.push_back(retset[marker].id);
          retset[marker].flag = false;
        }
        marker++;
      }

      // read nhoods of frontier ids
      std::vector<uint32_t> locked;
      if (!frontier.empty()) {
        if (stats != nullptr)
          stats->n_hops++;
        locked = this->lock_idx(idx_lock_table, kInvalidID, frontier, true);
        for (uint64_t i = 0; i < frontier.size(); i++) {
          uint32_t id = frontier[i];
          uint32_t loc = this->id2loc(id);
          uint64_t offset = loc_sector_no(loc) * SECTOR_LEN;
          auto sector_buf = sector_scratch + sector_scratch_idx * size_per_io;
          fnhood_t fnhood = std::make_tuple(id, loc, sector_buf);
          sector_scratch_idx++;
          frontier_nhoods.push_back(fnhood);
          frontier_read_reqs.emplace_back(
              IORequest(offset, size_per_io, sector_buf, u_loc_offset(loc), max_node_len, sector_scratch));
          if (stats != nullptr) {
            stats->n_4k++;
            stats->n_ios++;
          }
          num_ios++;
        }
        io_timer.reset();
        reader->read_alloc(frontier_read_reqs, ctx, &page_ref);

        if (stats != nullptr) {
          stats->io_us += (double) io_timer.elapsed();
        }
        this->unlock_idx(idx_lock_table, locked);
      }

      for (auto &frontier_nhood : frontier_nhoods) {
        auto [id, loc, sector_buf] = frontier_nhood;
        char *node_disk_buf = offset_to_loc(sector_buf, loc);
        unsigned *node_buf = offset_to_node_nhood(node_disk_buf);
        uint64_t nnbrs = (uint64_t) (*node_buf);
        T *node_fp_coords = offset_to_node_coords(node_disk_buf);

        T *node_fp_coords_copy = data_buf;
        memcpy(node_fp_coords_copy, node_fp_coords, data_dim * sizeof(T));
        float cur_expanded_dist = dist_cmp->compare(query, node_fp_coords_copy, (unsigned) aligned_dim);

        if (coord_map != nullptr) {
          if (unlikely(coord_buf == nullptr || coord_buf_idx > this->l_index * 10)) {
            LOG(ERROR) << "Please allocate larger coord_buf.";
            crash();
          }
          T *coord_ptr = coord_buf + coord_buf_idx * aligned_dim;
          memcpy(coord_ptr, node_fp_coords, data_dim * sizeof(T));
          coord_map->insert(std::make_pair(id, node_fp_coords_copy));
          coord_buf_idx++;
        }
        full_retset.push_back(Neighbor(id, cur_expanded_dist, true));

        // ========= 原始邻居 L0[id] =========
        unsigned *node_nbrs_raw = (node_buf + 1);

        // ========= 合并邻居 L0[id] ∪ L1[id] =========
        merged_nbrs.clear();
        merged_nbrs.reserve(nnbrs + 16);  // 预估一点 L1 容量，避免频繁扩容

        // 1) 先加 L0[id]（磁盘上的邻居）
        for (uint64_t m = 0; m < nnbrs; ++m) {
          unsigned nid = node_nbrs_raw[m];
          if (visited.find(nid) != visited.end())
            continue;
          visited.insert(nid);
          merged_nbrs.emplace_back(nid);
        }

        // 2) 再加 L1[id]（内存增量邻居）
        if (l1_table != nullptr) {
          l1_nbrs.clear();
          l1_table->append_neighbors(id, l1_nbrs);  // L1[id]
          // // 只打印前几十个点，避免刷屏
          // static thread_local int debug_cnt = 0;
          // if (debug_cnt < 50 && !l1_nbrs.empty()) {
          //     LOG(INFO) << "[L1-DEBUG] id=" << id
          //               << " has " << l1_nbrs.size()
          //               << " L1 neighbors, e.g. first=" << l1_nbrs[0];
          //     ++debug_cnt;
          // }
          for (unsigned nid : l1_nbrs) {
            if (visited.find(nid) != visited.end())
              continue;
            visited.insert(nid);
            merged_nbrs.emplace_back(nid);
          }
        }

        unsigned nbors_cand_size = (unsigned) merged_nbrs.size();
        if (!nbors_cand_size) {
          continue;   // 这个点没有可扩展邻居了
        }

        // compute merged_nbrs <-> query dist in PQ space
        cpu_timer.reset();
        nbr_handler->compute_dists(query_buf, merged_nbrs.data(), nbors_cand_size);
        if (stats != nullptr) {
          stats->n_cmps += (double) nbors_cand_size;
          stats->cpu_us += (double) cpu_timer.elapsed();
        }

        cpu_timer.reset();
        // process merged neighbors
        for (uint64_t m = 0; m < nbors_cand_size; ++m) {
          unsigned nbr_id = merged_nbrs[m];
          if (unlikely(nbr_id > this->cur_id)) {
            LOG(ERROR) << "ID is larger than current ID, " << nbr_id << " vs " << this->cur_id;
            crash();
          }

          cmps++;
          float dist = dist_scratch[m];
          if (stats != nullptr) {
            stats->n_cmps++;
          }
          if (dist >= retset[cur_list_size - 1].distance && (cur_list_size == l_search))
            continue;

          Neighbor nn(nbr_id, dist, true);
          auto r = InsertIntoPool(retset.data(), cur_list_size, nn);

          if (cur_list_size < l_search) {
            ++cur_list_size;
            if (unlikely(cur_list_size >= retset.size())) {
              retset.resize(2 * cur_list_size);
            }
          }

          if (r < nk)
            nk = r;  // nk 记录本轮扩展中最“前面”被更新的位置
        }

        if (dyn_search_l) {
          // TODO(gh): contention still exists in id2tag(x)
          // O(n), but it is not slow as L is typically smaller than 300.
          // l_search monotonically increases to handle deleted nodes.
          uint32_t tot = 0, cur = 0;
          for (cur = 0; cur < cur_list_size; ++cur) {
            uint32_t tag = id2tag(retset[cur].id);
            if (exclude_nodes->find(tag) == exclude_nodes->end()) {
              ++tot;
              if (tot == original_l_search) {
                break;
              }
            }
          }
          // cur is the stopped index (cur + 1 is the length it should be)
          l_search = std::max(original_l_search, cur + 1);
        }

        if (stats != nullptr) {
          stats->cpu_us += (double) cpu_timer.elapsed();
        }
      }

      // update best inserted position
      //

      if (nk <= k)
        k = nk;  // k is the best position in retset updated in this round.
      else
        ++k;

      hops++;
      if (stats != nullptr && stats->n_current_used != 0) {
        auto diskSearchEnd = std::chrono::high_resolution_clock::now();
        double elapsedSeconds =
            std::chrono::duration_cast<std::chrono::milliseconds>(diskSearchEnd - diskSearchBegin).count();
        if (elapsedSeconds >= stats->n_current_used)
          break;
      }
    }
    // re-sort by distance
    std::sort(full_retset.begin(), full_retset.end(),
              [](const Neighbor &left, const Neighbor &right) { return left < right; });

    if (passthrough_page_ref == nullptr) {
      reader->deref(&page_ref, ctx);
    }

    push_query_buf(query_buf);

    if (stats != nullptr) {
      stats->total_us = (double) query_timer.elapsed();
    }
  }

  template<typename T, typename TagT>
  size_t SSDIndex<T, TagT>::beam_search(const T *query, const uint64_t k_search, const uint32_t mem_L,
                                        const uint64_t l_search, TagT *res_tags, float *distances,
                                        const uint64_t beam_width, QueryStats *stats,
                                        tsl::robin_set<uint32_t> *deleted_nodes, bool dyn_search_l) {
    // iterate to fixed point
    std::shared_lock lk(merge_lock);
    std::vector<Neighbor> expanded_nodes_info;
    this->do_beam_search(query, mem_L, (uint32_t) l_search, (uint32_t) beam_width, expanded_nodes_info, nullptr,
                         nullptr, stats, deleted_nodes, dyn_search_l);
    uint64_t res_count = 0;
    for (uint32_t i = 0; i < l_search && res_count < k_search && i < expanded_nodes_info.size(); i++) {
      res_tags[res_count] = id2tag(expanded_nodes_info[i].id);
      distances[res_count] = expanded_nodes_info[i].distance;
      res_count++;
    }
    return res_count;
  }

  template class SSDIndex<float>;
  template class SSDIndex<int8_t>;
  template class SSDIndex<uint8_t>;
}  // namespace pipeann

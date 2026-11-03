#pragma once

#include <algorithm>
#include <thread>
#include <cstdlib>
#include <fstream>
#include <omp.h>
#include <chrono>
#include "gpu_verify.h"
#include "Kmeans.h"
#include "ClusterIO.h"
#include "Gorder.h"
#include "Cache.h"
#include "ConfigReader.h"

struct DiskJoin {
    void build(ConfigReader config) {
        one_level_kmeans(config);
    }

    void search(ConfigReader config) {
        // [GATE_GPU] 0 = original CPU verification, 1 = GPU verify (host
        // cache/IO path preserved), 2 = GPU verify (per-slot IO skipped,
        // whole cluster file resident in VRAM).
        int gpu_mode = 0;
        if (const char* e = getenv("GATE_GPU")) gpu_mode = atoi(e);
        using clk = std::chrono::steady_clock;
        double cand_s = 0, io_s = 0, verify_s = 0, gpu_h2d_s = 0, gpu_init_s = 0;
        float epsilon = sqrt(config.radius);
        ClusterReader cluster_reader(config.cluster_file, config.metadata_file, config.K);
        cluster_reader.readMetaData();
        size_t max_comp = cluster_reader.n / cluster_reader.cluster_num * config.K;
        size_t cluster_num = cluster_reader.cluster_num;
        size_t empty_count = 0;
        size_t d = cluster_reader.d;
        hnswlib::L2Space space(d);
        hnswlib::HierarchicalNSW<float>* graph = new hnswlib::HierarchicalNSW<float>(&space, config.hnsw_file);
        graph->radii = cluster_reader.radii;
        auto& bucket_sizes = cluster_reader.bucket_sizes;
        auto& assignment = cluster_reader.assignment;
        float* centroids = cluster_reader.centroids.data();
        std::vector<std::vector<size_t>> tasks(cluster_num);
        graph->setEf(1000);
        int len = 500;
        std::vector<float> arcos_list(len + 1);
        float sc = len / 2;
        for(int i = 0; i <= len; i++){
            float x = float(i - sc) / sc;
            float y = std::acos(x);
            arcos_list[i] = y;
        }

        auto arcos = [&](float x) -> float {
            if (x > 1) x = 1;
            int index = x*len/2 + len/2;
            return arcos_list[index];
        };
        auto g_c0 = clk::now();
#pragma omp parallel for
        for (size_t i = 0; i < cluster_num; i++) {
            auto top_candidates = graph->knnSearchBaseLayer(i, config.K);
            std::vector<std::pair<float, unsigned>> dis_to_boundary;
            while (!top_candidates.empty()) {
                auto neighbor_cluster = top_candidates.top().second;
                float temp = top_candidates.top().first / 2;
                top_candidates.pop();
                dis_to_boundary.emplace_back(temp, neighbor_cluster);
            }
            // [GATE4A] env-gated raw candidate dump (post-knn, pre-pruning).
            if (getenv("GATE4A_KNN_OUT")) {
                #pragma omp critical
                {
                    std::ofstream g4a_knn(getenv("GATE4A_KNN_OUT"), std::ios::app);
                    g4a_knn << i << " " << dis_to_boundary.size();
                    for (auto& c : dis_to_boundary) g4a_knn << " " << c.first << " " << c.second;
                    g4a_knn << "\n";
                }
            }
            std::sort(dis_to_boundary.begin(), dis_to_boundary.end());
            int ptr = dis_to_boundary.size() - 1;
            float sum_of_angle = 0;
            while (ptr >= 0) {
                sum_of_angle += arcos(dis_to_boundary[ptr].first / epsilon);
                if (sum_of_angle >= config.error_bound) break;
                ptr--;
            }
            for (int ii = 0; ii <= ptr; ii++) {
                if (i <= dis_to_boundary[ii].second) {
                    tasks[i].push_back(dis_to_boundary[ii].second);
                }
            }
            std::sort(tasks[i].begin(), tasks[i].end());
            if (tasks[i].size() == 0) {
                for (int ii = 0; ii <= ptr; ii++) {
                    if (dis_to_boundary[ii].first != 0) 
                        exit(0);
                }
                tasks[i].push_back(i);
            }
        }
        cand_s = std::chrono::duration<double>(clk::now() - g_c0).count();
        delete graph;
        size_t task_num = 0, max_task_num = 0;
        for (size_t i = 0; i < cluster_num; i++) {
            task_num += tasks[i].size();
            if (tasks[i].size() > max_task_num) max_task_num = tasks[i].size();
        }
        std::vector<size_t> perm(cluster_num);
        std::vector<size_t> order(cluster_num);
        std::vector<std::vector<size_t>> reordered_tasks(cluster_num);
        std::vector<std::vector<size_t>> shuffled_tasks(cluster_num);
        for (size_t i = 0; i < cluster_num; i++) {
            perm[i] = i;
        }
        for (size_t i = 0; i < cluster_num; i++) {
            shuffled_tasks[i] = tasks[perm[i]];
        }
        size_t budget = (size_t)(config.mem_budget * 1024 * 1024 * 1024);
        size_t length = cluster_reader.max_points * d;
        perm = order_gorder(shuffled_tasks, budget / 4 / length / config.K * 2);
        for (size_t i = 0; i < cluster_num; i++) {
            reordered_tasks[perm[i]] = shuffled_tasks[i];
            order[perm[i]] = i;
        }
        // [GATE4A] env-gated configuration decomposition: shows how ONE
        // mem_budget value simultaneously determines (a) the ClusterWriter
        // per-bucket write buffer used at build time, (b) this Cache capacity,
        // and (c) the Gorder window passed above. Print-only.
        if (getenv("GATE4A_STATS")) {
            size_t capacity = budget / 4 / length;
            size_t window = budget / 4 / length / config.K * 2;
            size_t writer_buffer = div_round_up(budget / cluster_num, d * 4) * d * 4;
            std::cerr << "[gate4a-config] n=" << (size_t)cluster_reader.n
                      << " d=" << d
                      << " cluster_num=" << cluster_num
                      << " max_points=" << cluster_reader.max_points
                      << " budget_bytes=" << budget
                      << " length=" << length
                      << " capacity_slots=" << capacity
                      << " K=" << config.K
                      << " window=" << window
                      << " window_lt_cluster_num=" << (window < cluster_num ? 1 : 0)
                      << " capacity_lt_cluster_num=" << (0 < capacity && capacity < cluster_num ? 1 : 0)
                      << " writer_buffer_bytes=" << writer_buffer
                      << " writer_buffer_vectors=" << (writer_buffer / (d * 4))
                      << " error_bound=" << config.error_bound
                      << " radius=" << config.radius
                      << " task_num_total=" << task_num
                      << " max_task_num=" << max_task_num
                      << "\n";
        }
        // [GATE4A] env-gated task-graph dump: line i is
        // "<slot> <target_bucket> <deg> <neighbour buckets...>" after the
        // Gorder reorder. The identity-order graph is recoverable because
        // the lists themselves are unmodified, only their placement permuted.
        if (getenv("GATE4A_TASK_OUT")) {
            std::ofstream g4a_tasks(getenv("GATE4A_TASK_OUT"));
            for (size_t i = 0; i < cluster_num; i++) {
                g4a_tasks << i << " " << order[i] << " " << reordered_tasks[i].size();
                for (auto nc : reordered_tasks[i]) g4a_tasks << " " << nc;
                g4a_tasks << "\n";
            }
        }
        // [GATE3] runtime invariant checks, gated, no effect on join logic.
        if (getenv("GATE3_INVARIANTS")) {
            std::vector<size_t> seen(cluster_num, 0);
            size_t perm_ok = 1, viol_head = 0, empty_tasks = 0, self_missing = 0;
            for (size_t i = 0; i < cluster_num; i++) {
                if (order[i] >= cluster_num || seen[order[i]]) { perm_ok = 0; }
                else seen[order[i]] = 1;
            }
            for (size_t i = 0; i < cluster_num; i++) {
                if (reordered_tasks[i].empty()) { empty_tasks++; continue; }
                if (reordered_tasks[i][0] != order[i]) viol_head++;
                bool has_self = false;
                for (auto nc : reordered_tasks[i]) if (nc == order[i]) has_self = true;
                if (!has_self) self_missing++;
            }
            size_t task_total = 0, upper_ok = 1;
            for (size_t i = 0; i < cluster_num; i++) {
                task_total += reordered_tasks[i].size();
                for (auto nc : reordered_tasks[i]) if (nc < order[i]) upper_ok = 0;
            }
            size_t sum_bucket = 0;
            for (auto s : bucket_sizes) sum_bucket += s;
            std::cerr << "[gate3-inv] perm_ok=" << perm_ok
                      << " empty_tasks=" << empty_tasks
                      << " head_mismatch=" << viol_head
                      << " self_missing=" << self_missing
                      << " upper_triangle_ok=" << upper_ok
                      << " task_total=" << task_total
                      << " bucket_sum=" << sum_bucket
                      << " n=" << (size_t)cluster_reader.n << "\n";
        }
        std::vector<float> data(max_task_num * length);

        // [GATE_GPU] lazy GPU verification state
        std::vector<float> g_all_vecs;
        std::vector<uint32_t> g_flat_ids;
        std::vector<size_t> g_id_off(cluster_num + 1, 0);
        if (gpu_mode > 0) {
            auto g_g0 = clk::now();
            size_t vfloats;
            if (gpu_mode == 2 || gpu_mode == 3) {
                // whole cluster file resident (host staging -> VRAM once)
                std::ifstream cf(config.cluster_file, std::ios::binary);
                g_all_vecs.resize(cluster_reader.n * d);
                cf.read((char*)g_all_vecs.data(), g_all_vecs.size() * 4);
                if (!cf) { std::cerr << "[gate-gpu] cluster read failed\n"; exit(1); }
                vfloats = g_all_vecs.size();
            } else {
                // mode 1: device arena used as per-slot scratch
                g_all_vecs.resize((size_t)max_task_num * length);
                vfloats = g_all_vecs.size();
            }
            size_t cum = 0;
            for (size_t b = 0; b < cluster_num; b++) {
                g_id_off[b] = cum;
                for (size_t j = 0; j < assignment[b].size(); j++)
                    g_flat_ids.push_back((uint32_t)assignment[b][j]);
                cum += assignment[b].size();
            }
            g_id_off[cluster_num] = cum;
            if (gpu_mode <= 2 &&
                gvu_init(vfloats, g_all_vecs.data(), g_flat_ids.size(), g_flat_ids.data(),
                         max_task_num) != 0) { std::cerr << "[gate-gpu] init failed\n"; exit(1); }
            gpu_init_s = std::chrono::duration<double>(clk::now() - g_g0).count();
            if (gpu_mode == 1) g_all_vecs.clear(); // staging not needed host-side
        }

        float io_size = 0;

        Cache cache(budget, length);
        cache.init(reordered_tasks);
        float sum = 0;
        size_t count = 0;
        size_t gpu_match_total = 0;
        float disk_time = 0;
        float comp_time = 0;
        float dist_comp = 0;
        // [GATE3] env-gated pair-output instrumentation. It records the same
        // hit condition used by the reference and does not alter candidate
        // generation, ordering, cache behaviour, pruning or distance logic.
        const char* gate3_pair_out = getenv("GATE3_PAIR_OUT");
        std::vector<std::vector<std::pair<size_t, size_t>>> gate3_pair_bufs;
        if (gate3_pair_out) gate3_pair_bufs.resize(omp_get_max_threads());
        for (size_t i = 0; i < cluster_num; i++) {
            auto target_cluster = order[i];
            auto& target_tasks = reordered_tasks[i];
            if (gpu_mode == 0 || gpu_mode == 1) {
                auto g_i0 = clk::now();
                for (size_t j = 0; j < target_tasks.size(); j++) {
                    auto neighbor_cluster = target_tasks[j];
                    if (!cache.find(neighbor_cluster, data.data() + j * length, cluster_reader.bucket_sizes[neighbor_cluster] * d)) {
                        cluster_reader.posixDirectReadCluster(neighbor_cluster, data.data() + j * length);
                        cache.push(neighbor_cluster, data.data() + j * length, cluster_reader.bucket_sizes[neighbor_cluster] * d);
                    }
                }
                io_s += std::chrono::duration<double>(clk::now() - g_i0).count();
            }
            
            if (bucket_sizes[target_cluster] == 0) continue;
            if (gpu_mode == 0) {
#pragma omp parallel for schedule(dynamic) reduction(+:sum) reduction(+:count) reduction(+:dist_comp)
            for (size_t j = 0; j < bucket_sizes[target_cluster]; j++) {
                auto id1 = assignment[target_cluster][j];
                float* vec1 = data.data() + j * d;
                std::vector<std::pair<size_t, size_t>>* gate3_local =
                    gate3_pair_out ? &gate3_pair_bufs[omp_get_thread_num()] : nullptr;
                for (size_t l = 0; l < bucket_sizes[target_cluster]; l++) {
                    auto id2 = assignment[target_cluster][l];
                    if (id2 >= id1) continue;
                    float* vec2 = data.data() + l * d;
                    float dist = dist_l2(vec1, vec2, &d);
                    dist_comp++;
                    if (dist < epsilon * epsilon) {
                        if (id1 % 100000 == 0) count++;
                        if (id2 % 100000 == 0) count++;
                        if (gate3_local) gate3_local->emplace_back(std::min(id1, id2), std::max(id1, id2));
                    }
                }

                for (int k = 1; k < target_tasks.size(); k++) {
                    auto neighbor_cluster = target_tasks[k];
                    float dist = dist_l2(vec1, centroids + neighbor_cluster * d, &d);
                    for (size_t l = 0; l < bucket_sizes[neighbor_cluster]; l++) {
                        auto id2 = assignment[neighbor_cluster][l];
                        float* vec2 = data.data() + k * length + l * d;
                        float dist1 = dist_l2(vec1, vec2, &d);
                        dist_comp++;
                        if (dist1 < epsilon * epsilon) {
                            if (id1 % 100000 == 0) count++;
                            if (id2 % 100000 == 0) count++;
                            if (gate3_local) gate3_local->emplace_back(std::min(id1, id2), std::max(id1, id2));
                        };
                    }
                }
            }
            } else if (gpu_mode == 3) {
                // [GATE_GPU] DRAM-resident CPU verification (IO skipped):
                // same omp loops as native but reading a whole-file DRAM copy.
                // Same-IO-regime CPU control for mode 2 (VRAM resident GPU).
                auto g_v0 = clk::now();
                const float* allv = g_all_vecs.data();
                size_t tbase = cluster_reader.file_pos[target_cluster] / 4;
#pragma omp parallel for schedule(dynamic) reduction(+:count) reduction(+:dist_comp)
                for (size_t j = 0; j < bucket_sizes[target_cluster]; j++) {
                    auto id1 = assignment[target_cluster][j];
                    const float* vec1 = allv + tbase + j * d;
                    for (size_t l = 0; l < bucket_sizes[target_cluster]; l++) {
                        auto id2 = assignment[target_cluster][l];
                        if (id2 >= id1) continue;
                        const float* vec2 = allv + tbase + l * d;
                        float dist = dist_l2(vec1, vec2, &d);
                        dist_comp++;
                        if (dist < epsilon * epsilon) {
                            if (id1 % 100000 == 0) count++;
                            if (id2 % 100000 == 0) count++;
                        }
                    }
                    for (int k = 1; k < (int)target_tasks.size(); k++) {
                        auto neighbor_cluster = target_tasks[k];
                        size_t nbase = cluster_reader.file_pos[neighbor_cluster] / 4;
                        for (size_t l = 0; l < bucket_sizes[neighbor_cluster]; l++) {
                            auto id2 = assignment[neighbor_cluster][l];
                            const float* vec2 = allv + nbase + l * d;
                            float dist1 = dist_l2(vec1, vec2, &d);
                            dist_comp++;
                            if (dist1 < epsilon * epsilon) {
                                if (id1 % 100000 == 0) count++;
                                if (id2 % 100000 == 0) count++;
                            }
                        }
                    }
                }
                verify_s += std::chrono::duration<double>(clk::now() - g_v0).count();
            } else {
                // [GATE_GPU] batched GPU verification for this slot.
                // Task 0 is the same-bucket self join (target bucket);
                // tasks k>=1 are cross joins target x neighbor_k.
                auto g_v0 = clk::now();
                size_t tm = bucket_sizes[target_cluster];
                size_t scratch_off = 0;
                const float* dev_base = gvu_vecs_base();
                if (gpu_mode == 1) {
                    if (tm > 0) {
                        gvu_arena_upload(0, data.data(), tm * d);
                        scratch_off = tm * d;
                    }
                }
                std::vector<GvuTask> gtasks;
                gtasks.reserve(target_tasks.size());
                for (int k = 0; k < (int)target_tasks.size(); k++) {
                    auto b = target_tasks[k];
                    size_t nb = bucket_sizes[b];
                    GvuTask t;
                    t.d = (uint32_t)d;
                    t.ida = gvu_ids_base() + g_id_off[target_cluster];
                    t.idb = gvu_ids_base() + g_id_off[b];
                    if (k == 0) {
                        if (tm == 0) continue;
                        t.same = 1; t.m = (uint32_t)tm; t.n = (uint32_t)tm;
                        t.A = (gpu_mode == 1) ? dev_base
                                              : dev_base + cluster_reader.file_pos[target_cluster] / 4;
                        t.B = t.A;
                    } else {
                        if (nb == 0 || tm == 0) continue;
                        t.same = 0; t.m = (uint32_t)tm; t.n = (uint32_t)nb;
                        t.A = (gpu_mode == 1) ? dev_base
                                              : dev_base + cluster_reader.file_pos[target_cluster] / 4;
                        if (gpu_mode == 1) {
                            gvu_arena_upload(scratch_off, data.data() + (size_t)k * length, nb * d);
                            t.B = dev_base + scratch_off;
                            scratch_off += nb * d;
                        } else {
                            t.B = dev_base + cluster_reader.file_pos[b] / 4;
                        }
                    }
                    gtasks.push_back(t);
                }
                unsigned long long bm = 0, bs2 = 0;
                gvu_run(gtasks.data(), (int)gtasks.size(), epsilon * epsilon, &bm, &bs2);
                count += (size_t)bs2;
                gpu_match_total += bm;
                for (int k = 0; k < (int)target_tasks.size(); k++) {
                    auto b = target_tasks[k];
                    if (k == 0) dist_comp += (uint64_t)tm * (tm - 1) / 2;
                    else dist_comp += (uint64_t)tm * bucket_sizes[b];
                }
                verify_s += std::chrono::duration<double>(clk::now() - g_v0).count();
            }
        }std::cout << "recall = " << 1.0 * count / config.gt << "\n";
        {
            std::cerr << "[gate-gpu] mode=" << gpu_mode
                      << " cand_s=" << cand_s
                      << " io_s=" << io_s
                      << " verify_s=" << verify_s << " gpu_init_s=" << gpu_init_s
                      << " matches=" << (gpu_mode > 0 ? gpu_match_total : (size_t)0)
                      << " dist_comp=" << (size_t)dist_comp;
            if (gpu_mode > 0) { std::cerr << " peak_vram=" << gvu_peak_vram_bytes(); gvu_finalize(); }
            std::cerr << "\n";
        }
        cache.g4a_stats(); // [GATE4A] env-gated cache mechanism statistics
        // [GATE3] precise statistics, gated.
        if (getenv("GATE3_INVARIANTS")) {
            std::cerr << "[gate3-stat] dist_comp=" << (size_t)dist_comp
                      << " sampled_count=" << count
                      << " gt=" << config.gt << "\n";
        }
        // [GATE3] write per-thread pair buffers (thread-local -> no locking).
        if (gate3_pair_out) {
            std::ofstream gate3_f(gate3_pair_out);
            size_t gate3_total = 0;
            for (auto& gate3_pb : gate3_pair_bufs) {
                for (auto& gate3_pr : gate3_pb) {
                    gate3_f << gate3_pr.first << " " << gate3_pr.second << "\n";
                    gate3_total++;
                }
            }
            gate3_f.close();
            std::cerr << "[gate3] pair_dump=" << gate3_pair_out
                      << " pairs=" << gate3_total
                      << " threads=" << gate3_pair_bufs.size() << "\n";
        }
    }
};

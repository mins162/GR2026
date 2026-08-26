#include "graph.hpp"
#include "nvtx_profile.hpp"

namespace cudb {
struct net;
bool cpu_tree_center_enabled();
int cpu_tree_center_min_degree();
int cpu_tree_center_root(const net &target, int legacy_root);
void reset_cpu_tree_center_profile();
void print_cpu_tree_center_profile(const char *stage);
}

namespace Lshape_route {

//declaration
void Lshape_route(vector<int> &nets2route);

//implementation

__global__ void Lshape_route_cuda(int net_cnt, int net_offset, int *node_cnt_sum, int *nodes, int *par_nodes, double *dist, int *from, int *layer_range, int stamp) {
    int net_idx = blockIdx.x * blockDim.x + threadIdx.x;// net_idx-th net in this batch
    if(net_idx >= net_cnt) return;
    net_idx += net_offset;
    int node_cnt = node_cnt_sum[net_idx + 1] - node_cnt_sum[net_idx];// node count of the net
    int *net_routes = routes + pin_acc_num[net_ids[net_idx]] * ROUTE_PER_PIN;
    nodes += node_cnt_sum[net_idx];
    par_nodes += node_cnt_sum[net_idx];
    layer_range += node_cnt_sum[net_idx];
    dist += (node_cnt_sum[net_idx] - node_cnt_sum[net_offset]) * L * L;
    from += (node_cnt_sum[net_idx] - node_cnt_sum[net_offset]) * L * L;
    //compute the via cost for each node and each layer range pair 
    // node_dist[minl * L + maxl] is the total via cost to include layers in [minl, maxl]
    for(int i = 0; i < node_cnt; i++) {
        int l = nodes[i] / X / Y, x = nodes[i] / Y % X, y = nodes[i] % Y;
        double *node_dist = dist + i * L * L;
        for(int minl = 0; minl < L; minl++) {
            node_dist[minl * L + minl] = 0;
            for(int maxl = minl + 1; maxl < L; maxl++)
                node_dist[minl * L + maxl] = node_dist[minl * L + maxl - 1] + vcost[IDX(maxl - 1, x, y)];
            for(int maxl = minl; maxl < L; maxl++)
                if(l < L && (minl > l || maxl < l)) node_dist[minl * L + maxl] = INF;
        }
    }
    for(int i = node_cnt - 1; i >= 1; i--) {
        int x = nodes[i] / Y % X, y = nodes[i] % Y;// current node
        int px = nodes[par_nodes[i]] / Y % X, py = nodes[par_nodes[i]] % Y;// parent node of current node
        int minx = min(x, px), maxx = max(x, px), miny = min(y, py), maxy = max(y, py);
        double *node_dist = dist + i * L * L, *par_dist = dist + par_nodes[i] * L * L;
        assert(par_nodes[i] < i);
        int *prev = from + i * L * L, cur_from[10];
        double min_cost_cur[10], min_cost_par[100];
        for(int l = 0; l < L; l++) {
            min_cost_cur[l] = min_cost_par[l * L + l] = INF;
            for(int minl = 0; minl <= l; minl++)
                for(int maxl = l; maxl < L; maxl++)
                    if(node_dist[minl * L + maxl] < min_cost_cur[l]) {
                        min_cost_cur[l] = node_dist[minl * L + maxl];
                        cur_from[l] = minl * L + maxl;
                    }
        }
        if(x == px || y == py) {
            for(int l = 0; l < L; l++) {
                if((l & 1 ^ DIR) == 0 && y != py) continue;
                if((l & 1 ^ DIR) == 1 && x != px) continue;
                min_cost_par[l * L + l] = min_cost_cur[l] + graph::wire_segment_cost(l, minx, maxx, miny, maxy);//presum[IDX(l, maxx, maxy)] - presum[IDX(l, minx, miny)];
                prev[l * L + l] = cur_from[l] * L * L + l * L + l;
            }
        } else {
            for(int curl = 0; curl < L; curl++) {
                double cost = min_cost_cur[curl];
                if(curl & 1 ^ DIR)
                    cost += graph::wire_segment_cost(curl, x, x, miny, maxy);//presum[IDX(curl, x, maxy)] - presum[IDX(curl, x, miny)];
                else
                    cost += graph::wire_segment_cost(curl, minx, maxx, y, y);//presum[IDX(curl, maxx, y)] - presum[IDX(curl, minx, y)];
                for(int parl = curl & 1 ^ 1; parl < L; parl += 2) {// curl and parl must have different routing directions
                    assert(curl % 2 != parl % 2);
                    double cost2 = 0;
                    for(int l = min(curl, parl) + 1; l < max(curl, parl); l++)
                        cost2 += (curl & 1 ^ DIR) ? vcost[IDX(l, x, py)] : vcost[IDX(l, px, y)];
                    if(parl & 1 ^ DIR)
                        cost2 += graph::wire_segment_cost(parl, px, px, miny, maxy);//presum[IDX(parl, px, maxy)] - presum[IDX(parl, px, miny)];
                    else
                        cost2 += graph::wire_segment_cost(parl, minx, maxx, py, py);//presum[IDX(parl, maxx, py)] - presum[IDX(parl, minx, py)];
                    if(cost + cost2 < min_cost_par[parl * L + parl]) {
                        min_cost_par[parl * L + parl] = cost + cost2;
                        prev[parl * L + parl] = cur_from[curl] * L * L + curl * L + parl;
                    }
                }
            }
        }


        for(int minl = 0; minl < L; minl++) {
            for(int maxl = minl + 1; maxl < L; maxl++) {
                //min_cost_par[minl * L + maxl] = min { min_cost_par[minl * L + maxl - 1], min_cost_par[maxl * L + maxl] }
                if(min_cost_par[minl * L + maxl - 1] <= min_cost_par[maxl * L + maxl]) {
                    min_cost_par[minl * L + maxl] = min_cost_par[minl * L + maxl - 1];
                    prev[minl * L + maxl] = prev[minl * L + maxl - 1];
                } else {
                    min_cost_par[minl * L + maxl] = min_cost_par[maxl * L + maxl];
                    prev[minl * L + maxl] = prev[maxl * L + maxl];
                }
            }
            for(int maxl = minl; maxl < L; maxl++) {
                par_dist[minl * L + maxl] += min_cost_par[minl * L + maxl];
            }
        }
    }

    net_routes[0] = 1;
    layer_range[0] = 0;
    for(int minl = 0; minl < L; minl++)
        for(int maxl = minl; maxl < L; maxl++) 
            if(dist[minl * L + maxl] < dist[layer_range[0]]) {
                layer_range[0] = minl * L + maxl;
            }
    for(int i = 0; i < node_cnt; i++) {
        int *prev = from + i * L * L;
        if(i > 0) layer_range[i] = prev[layer_range[par_nodes[i]]] / L / L;
        assert(dist[i * L * L + layer_range[i]] < INF);
        int minl = layer_range[i] / L, maxl = layer_range[i] % L, x = nodes[i] / Y % X, y = nodes[i] % Y;
        if(minl < maxl) {
            net_routes[net_routes[0]++] = IDX(minl, x, y);
            net_routes[net_routes[0]++] = IDX(maxl, x, y);
        }

        if(i == 0) continue;
        int px = nodes[par_nodes[i]] / Y % X, py = nodes[par_nodes[i]] % Y;
        int minx = min(x, px), maxx = max(x, px), miny = min(y, py), maxy = max(y, py);
        int curl = prev[layer_range[par_nodes[i]]] / L % L, parl = prev[layer_range[par_nodes[i]]] % L;
        if(px == x || py == y) {
            assert(curl == parl);
            net_routes[net_routes[0]++] = IDX(curl, minx, miny);
            net_routes[net_routes[0]++] = IDX(curl, maxx, maxy);
            graph::atomic_add_unit_demand_wire_segment(curl, minx, maxx, miny, maxy, stamp);
        } else {        
            assert(curl % 2 != parl % 2);
            int minl = min(curl, parl), maxl = max(curl, parl);
            if(curl & 1 ^ DIR) {
                net_routes[net_routes[0]++] = IDX(curl, x, y);
                net_routes[net_routes[0]++] = IDX(curl, x, py);
                graph::atomic_add_unit_demand_wire_segment(curl, x, x, miny, maxy, stamp);

                net_routes[net_routes[0]++] = IDX(curl, x, py);
                net_routes[net_routes[0]++] = IDX(parl, x, py);

                net_routes[net_routes[0]++] = IDX(parl, x, py);
                net_routes[net_routes[0]++] = IDX(parl, px, py);
                graph::atomic_add_unit_demand_wire_segment(parl, minx, maxx, py, py, stamp);
            } else {
                net_routes[net_routes[0]++] = IDX(curl, x, y);
                net_routes[net_routes[0]++] = IDX(curl, px, y);
                graph::atomic_add_unit_demand_wire_segment(curl, minx, maxx, y, y, stamp);

                net_routes[net_routes[0]++] = IDX(curl, px, y);
                net_routes[net_routes[0]++] = IDX(parl, px, y);

                net_routes[net_routes[0]++] = IDX(parl, px, y);
                net_routes[net_routes[0]++] = IDX(parl, px, py);
                graph::atomic_add_unit_demand_wire_segment(parl, px, px, miny, maxy, stamp);
            }
        }
    }
}

void Lshape_route(vector<int> &nets2route) {
    double Lshape_start_time = elapsed_time();


    if(LOG) printf("[%5.1f] Stage 1 initial routing: RSMT (CPU/GPU FLUTE) starts\n", elapsed_time());
    const bool use_gpu_flute = gpu_flute_enabled();
    const int gpu_min_degree = GPU_FLUTE_MIN_DEGREE;
    vector<int> gpu_flute_nets;
    gpu_flute_nets.reserve(nets2route.size() / 100);
    int cpu_flute_net_count = 0;
    for(int net_id : nets2route) {
        if(use_gpu_flute && gpu_flute_takes_degree(nets[net_id].pins.size()))
            gpu_flute_nets.emplace_back(net_id);
        else
            ++cpu_flute_net_count;
    }
    // Launch the high-degree GPU-FLUTE batch on its own host thread so it
    // overlaps the low-degree CPU FLUTE loop below.  The two paths write
    // disjoint net sets and share only read-only inputs (the pin CSR
    // buffers and the FLUTE LUT loaded in main()), so the join is the only
    // synchronization needed.  record_runtime_stage() appends to a global
    // vector and therefore stays on this thread: the CPU stage covers the
    // overlapped region and the GPU stage only the tail beyond it.
    const double rsmt_start_time = elapsed_time();
    const bool overlap_gpu_flute = flute_overlap_enabled();
    thread gpu_flute_thread;
    double gpu_flute_wall = 0;
    if(use_gpu_flute && !gpu_flute_nets.empty()) {
        if(LOG) {
            const char *schedule = overlap_gpu_flute ? "launched overlapped" : "serial (overlap off)";
            if(gpu_flute_max_degree() == INT_MAX)
                printf("[%5.1f] Stage 1 RSMT: GPU degree >= %d, nets=%zu, %s\n",
                       elapsed_time(), gpu_min_degree, gpu_flute_nets.size(), schedule);
            else
                printf("[%5.1f] Stage 1 RSMT: GPU degree in [%d, %d], nets=%zu, %s\n",
                       elapsed_time(), gpu_min_degree, gpu_flute_max_degree(),
                       gpu_flute_nets.size(), schedule);
        }
        if(overlap_gpu_flute) {
            gpu_flute_thread = thread([&gpu_flute_nets, &gpu_flute_wall, rsmt_start_time] {
                construct_rsmt_gpu(gpu_flute_nets);
                gpu_flute_wall = elapsed_time() - rsmt_start_time;
            });
        } else {
            construct_rsmt_gpu(gpu_flute_nets);
            gpu_flute_wall = elapsed_time() - rsmt_start_time;
            if(LOG) printf("[%5.1f] Stage 1 RSMT: GPU wall=%.3fs, serial before the CPU loop\n",
                           elapsed_time(), gpu_flute_wall);
            record_runtime_stage("  S1: RSMT, GPU FLUTE (serial)", rsmt_start_time);
        }
    }
    // With the overlap on this is the thread spawn away from rsmt_start_time;
    // with it off it excludes the GPU batch that already ran above.
    const double cpu_flute_start_time = elapsed_time();
    #pragma omp parallel for num_threads(8)
    for(int i = 0; i < nets2route.size(); i++) {
        // Keep the original CPU FLUTE implementation for root nets that fit
        // in its LUT.  GPU-FLUTE receives only high-degree roots; its internal
        // low-degree subnets are solved by the device LUT before reverse merge.
        if(!use_gpu_flute || !gpu_flute_takes_degree(nets[nets2route[i]].pins.size()))
            nets[nets2route[i]].construct_rsmt();
    }
    if(LOG) printf("[%5.1f] Stage 1 RSMT: CPU degree < %d, nets=%d, wall=%.3fs\n",
                   elapsed_time(), gpu_min_degree, cpu_flute_net_count,
                   elapsed_time() - cpu_flute_start_time);
    record_runtime_stage(overlap_gpu_flute ? "  S1: RSMT, CPU FLUTE (overlapped)"
                                           : "  S1: RSMT, CPU FLUTE (serial)",
                         cpu_flute_start_time);
    if(gpu_flute_thread.joinable()) {
        const double gpu_join_start_time = elapsed_time();
        gpu_flute_thread.join();
        if(LOG) printf("[%5.1f] Stage 1 RSMT: GPU wall=%.3fs, tail beyond CPU loop=%.3fs\n",
                       elapsed_time(), gpu_flute_wall, elapsed_time() - gpu_join_start_time);
        record_runtime_stage("  S1: RSMT, GPU FLUTE tail", gpu_join_start_time);
    }
    if(LOG) printf("[%5.1f] Stage 1 initial routing: RSMT (CPU/GPU FLUTE) ends\n", elapsed_time());
    write_rsmt_depth_profile(nets2route);


    //generate batches
    
    if(LOG) printf("[%5.1f] Stage 1 initial routing: net ordering starts\n", elapsed_time());
    sort(nets2route.begin(), nets2route.end(), [] (int l, int r) {
        return nets[l].hpwl > nets[r].hpwl;
    });
    if(LOG) printf("[%5.1f] Stage 1 initial routing: net ordering ends\n", elapsed_time());
    
    if(LOG) printf("[%5.1f] Stage 1 initial routing: batch generation starts\n", elapsed_time());
    const double batch_gen_start_time = elapsed_time();
    auto batches = generate_batches_rsmt(nets2route);
    record_runtime_stage("  S1: batch generation", batch_gen_start_time);
    if(LOG) printf("[%5.1f] Stage 1 initial routing: batch generation ends\n", elapsed_time());
    reverse(batches.begin(), batches.end());

    vector<int> batch_cnt_sum(batches.size() + 1, 0);
    for(int i = 0; i < batches.size(); i++) {
        batch_cnt_sum[i + 1] = batch_cnt_sum[i] + batches[i].size();
        for(int j = 0; j < batches[i].size(); j++)
            nets2route[batch_cnt_sum[i] + j] = batches[i][j];
    }
    int pin_cnt = 0, net_cnt = nets2route.size();
    for(auto net_id : nets2route) pin_cnt += nets[net_id].pins.size();
    int *node_cnt_sum_cpu = new int[net_cnt + 1]();
    int *nodes_cpu = new int[pin_cnt * 2];
    int *par_nodes_cpu = new int[pin_cnt * 2];


    if(LOG) printf("[%5.1f] Stage 1 initial routing: routing-DAG DFS starts\n", elapsed_time());
    const double dag_dfs_start_time = elapsed_time();
    cudb::reset_cpu_tree_center_profile();
    for(int id = 0; id < net_cnt; id++) {
        auto &target = nets[nets2route[id]];
        auto &graph = target.rsmt;
        function<void(int, int, int)> dfs = [&] (int x, int par, int par_node_idx) {
            int node_idx = node_cnt_sum_cpu[id + 1]++;
            nodes_cpu[node_cnt_sum_cpu[id] + node_idx] = graph.back()[x];
            par_nodes_cpu[node_cnt_sum_cpu[id] + node_idx] = par_node_idx;
            for(auto e : graph[x]) if(e != par) dfs(e, x, node_idx);
        };
        int root = 0; // Original Stage-1 basic-DAG root.
        if(cudb::cpu_tree_center_enabled() &&
           target.pins.size() >= cudb::cpu_tree_center_min_degree())
            root = cudb::cpu_tree_center_root(target, root);
        dfs(root, -1, -1);
        node_cnt_sum_cpu[id + 1] += node_cnt_sum_cpu[id];
    }
    cudb::print_cpu_tree_center_profile("Stage 1");
    record_runtime_stage("  S1: DAG build (DFS)", dag_dfs_start_time);
    if(LOG) printf("[%5.1f] Stage 1 initial routing: routing-DAG DFS ends\n", elapsed_time());
    int max_num_nodes = 0;
    for(int i = 0; i < batches.size(); i++)
        max_num_nodes = max(max_num_nodes, node_cnt_sum_cpu[batch_cnt_sum[i + 1]] - node_cnt_sum_cpu[batch_cnt_sum[i]]);

    double *dist;
    int *from, *layer_range, *node_cnt_sum, *nodes, *par_nodes;

    print_GPU_memory_usage();
    cudaMemcpy(net_ids, nets2route.data(), net_cnt * sizeof(int), cudaMemcpyHostToDevice);

    cudaMalloc(&node_cnt_sum, (net_cnt + 1) * sizeof(int));
    cudaMemcpy(node_cnt_sum, node_cnt_sum_cpu, (net_cnt + 1) * sizeof(int), cudaMemcpyHostToDevice);
    cudaMalloc(&nodes, node_cnt_sum_cpu[net_cnt] * sizeof(int));
    cudaMemcpy(nodes, nodes_cpu, node_cnt_sum_cpu[net_cnt] * sizeof(int), cudaMemcpyHostToDevice);
    cudaMalloc(&par_nodes, node_cnt_sum_cpu[net_cnt] * sizeof(int));
    cudaMemcpy(par_nodes, par_nodes_cpu, node_cnt_sum_cpu[net_cnt] * sizeof(int), cudaMemcpyHostToDevice);

    print_GPU_memory_usage();
    cudaMalloc(&dist, max_num_nodes * L * L * sizeof(double));
    cudaMalloc(&from, max_num_nodes * L * L * sizeof(int));
    cudaMalloc(&layer_range, node_cnt_sum_cpu[net_cnt] * sizeof(int));
    
    print_GPU_memory_usage();
    
    if(LOG) printf("[%5.1f] Stage 1 initial routing: L-shape DAG GPU route starts\n", elapsed_time());
    const double gpu_route_start_time = elapsed_time();
     for(int i = 0; i < batches.size(); i++) {
        NVTX_RANGE("S1/batch", STAGE);
        global_timestamp++;
        NVTX_PUSH("S1/update_cost", UPDATE_COST);
        graph::update_cost();
        NVTX_POP();
        NVTX_PUSH("S1/compute_presum", PRESUM);
        graph::compute_presum<<<all_track_cnt, THREAD_NUM, sizeof(double) * XY>>> ();
        graph::finish_cost_refresh();
        NVTX_POP();
        NVTX_PUSH("S1/DP", BOTTOM_UP);
        Lshape_route_cuda<<<BLOCK_NUM(batches[i].size()), THREAD_NUM>>> (batches[i].size(), batch_cnt_sum[i], node_cnt_sum, nodes, par_nodes, dist, from, layer_range, global_timestamp);
        NVTX_POP();
        NVTX_PUSH("S1/commit", COMMIT);
        graph::batch_wire_update(global_timestamp);
        graph::commit_via_demand<<<BLOCK_NUM(batches[i].size()), THREAD_NUM>>> (batches[i].size(), batch_cnt_sum[i], global_timestamp);
        NVTX_POP();
    }
    cudaDeviceSynchronize();
    record_runtime_stage("  S1: GPU route batches", gpu_route_start_time);
    if(LOG) printf("[%5.1f] Stage 1 initial routing: L-shape DAG GPU route ends\n", elapsed_time());

    cudaFree(node_cnt_sum);
    cudaFree(nodes);
    cudaFree(par_nodes);
    cudaFree(dist);
    cudaFree(from);
    cudaFree(layer_range);

    printf("Stage 1 initial routing: GPU memory after route.   ");
    print_GPU_memory_usage();

    Lshape_time = elapsed_time() - Lshape_start_time;
    if(LOG) printf("[%5.1f] Stage 1 initial routing ends\n", elapsed_time());
}

}

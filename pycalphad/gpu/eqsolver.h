#ifndef EQSOLVER_H
#define EQSOLVER_H

#include "minimizer.h" // REQUIRED: Contains SystemSpecification, SystemState, constants, etc.

// --- Helper Structs for GPU Data ---

// To represent the grid data (from pycalphad calculate output) on the GPU
typedef struct DeviceGrid {
    const double* Y_ptr;    // Flattened array of site fractions for all grid points
    const double* X_ptr;    // Flattened array of mole compositions for all grid points
    const double* GM_ptr;   // Array of Gibbs energies for all grid points
    const int* PhaseID_ptr; // Flattened array of phase identifiers for all grid points
                            // (integer IDs mapping to PhaseRecord in DevicePhaseData)

    int num_grid_points_total; // Total number of rows in the grid arrays
    int phase_dof_stride_Y;    // Max number of site fractions for any phase (stride for Y_ptr)
    int num_components_stride_X; // Number of components (stride for X_ptr)

    // For add_nearly_stable: mapping a global phase ID to its start/end row in the grid
    // This replaces grid.attrs['phase_indices']
    const int* phase_grid_indices_start; // Array indexed by global phase ID
    const int* phase_grid_indices_stop;  // Array indexed by global phase ID
    int num_mappable_phases_in_grid;   // Size of phase_grid_indices_start/stop arrays
} DeviceGrid;

// To represent PhaseRecord data on the GPU
typedef struct DevicePhaseData {
    const PhaseRecord* phase_records_array; // Pointer to an array of unique PhaseRecord structs
    int num_unique_phase_records;
    // If a mapping from a simple active_phase_id (0 to N_active_phases-1) to
    // an index in phase_records_array is needed, it can be passed or handled by caller.
    // For now, assume direct indexing or that CompositionSet stores a direct pointer or fat index.
    const int* grid_phase_id_to_record_index; // Array sized by max grid phase ID
    int max_grid_phase_id;
} DevicePhaseData;


// --- Forward Declarations ---
__device__ int get_phase_record_index(const DevicePhaseData* phase_data, int grid_phase_id);

// --- Device Helper Functions ---

__device__ int argmax_gpu(const double* arr, int size) {
    if (size <= 0) return -1; // Or handle error appropriately
    int max_idx = 0;
    double max_val = arr[0];
    for (int i = 1; i < size; ++i) {
        if (arr[i] > max_val) {
            max_val = arr[i];
            max_idx = i;
        }
    }
    return max_idx;
}


/**
 * @brief Attempts to add a new phase with the largest driving force.
 * GPU equivalent of add_new_phases from eqsolver.pyx.py.
 *
 * @param added_phase_grid_idx Output: If a phase is added, this will be its index in the DeviceGrid.
 * @param current_sys_state Pointer to the current SystemState (contains chemical_potentials, compsets).
 * This function will try to find a candidate to add.
 * The actual addition to compsets array is handled by the caller.
 * @param spec System-wide specification.
 * @param grid_data Pointer to the grid data on the GPU.
 * @param phase_data Pointer to the phase record data on the GPU.
 * @param state_variables_values Current P, T, etc. for this condition.
 * @param minimum_df Minimum driving force to consider adding a phase.
 * @param removed_compsets Array of CompositionSets that were recently removed (for distinctness check).
 * @param num_removed_compsets Number of compsets in removed_compsets array.
 * @return True if a candidate phase is identified (caller then adds it), false otherwise.
 */
__device__ bool identify_candidate_phase_to_add(
    int* candidate_phase_grid_idx,         // Output: index in grid for the phase to add
    double* candidate_driving_force,       // Output: driving force of the candidate
    const SystemState* current_sys_state,  // Input: for chemical potentials, existing compsets
    const SystemSpecification* spec,
    const DeviceGrid* grid_data,
    const DevicePhaseData* phase_data,
    const double* state_variables_values,  // Current P, T for potential new phase
    double minimum_df,
    const CompositionSet* removed_compsets, // Array of recently removed CompositionSets
    int num_removed_compsets               // Number of removed compsets
) {
    if (grid_data->num_grid_points_total == 0) return false;

    // Calculate driving forces for all points in the grid
    // double driving_forces_on_grid[MAX_GRID_POINTS]; // MAX_GRID_POINTS needs to be a define
    // This dynamic allocation or large static array is problematic.
    // Process grid points sequentially or in chunks if too large for local static memory.
    // For now, assume we can iterate and find max on the fly.

    double largest_df = -1e30; // Negative infinity
    int best_grid_idx = -1;

    for (int i = 0; i < grid_data->num_grid_points_total; ++i) {
        double current_potential_energy = 0.0;
        for (int comp_idx = 0; comp_idx < spec->num_components; ++comp_idx) {
            // X_ptr is [grid_point_idx * num_components_stride_X + comp_idx]
            current_potential_energy += grid_data->X_ptr[i * grid_data->num_components_stride_X + comp_idx] *
                                        current_sys_state->chemical_potentials[comp_idx];
        }
        double df = current_potential_energy - grid_data->GM_ptr[i];

        if (df > largest_df) {
            int candidate_phase_id_from_grid = grid_data->PhaseID_ptr[i];
            if (candidate_phase_id_from_grid == -1) continue; // _FAKE_ or invalid phase in grid

            int candidate_record_index = get_phase_record_index(phase_data, candidate_phase_id_from_grid);
            if (candidate_record_index == -1) continue; // Invalid phase

            const PhaseRecord* candidate_phase_record = &phase_data->phase_records_array[candidate_record_index];
            
            // --- Primary distinctness check against removed compsets (matching CPU logic exactly) ---
            bool distinct_from_removed = true;
            for (int rem_idx = 0; rem_idx < num_removed_compsets; ++rem_idx) {
                const CompositionSet* removed_compset = &removed_compsets[rem_idx];
                
                // Check if same phase type (matching CPU: df_phase_name != compset.phase_record.phase_name)
                if (removed_compset->phase_record != candidate_phase_record) {
                    continue;
                }
                
                // Same phase type, check site fraction composition (matching CPU pyx logic lines 41-47)
                distinct_from_removed = false;
                for (int dof_idx = 0; dof_idx < candidate_phase_record->phase_dof; ++dof_idx) {
                    double candidate_site_frac = grid_data->Y_ptr[i * grid_data->phase_dof_stride_Y + dof_idx];
                    double removed_site_frac = removed_compset->dof[spec->num_statevars + dof_idx];
                    
                    // Use 10*COMP_DIFFERENCE_TOL as in CPU version (line 43 in pyx)
                    if (fabs(candidate_site_frac - removed_site_frac) > 10.0 * COMP_DIFFERENCE_TOL) {
                        distinct_from_removed = true;
                        break;
                    }
                }
                
                if (!distinct_from_removed) {
                    break; // Found a non-distinct match, skip this candidate
                }
            }
            
            if (!distinct_from_removed) {
                continue; // Skip this candidate, not distinct from removed phases (matching CPU line 51)
            }
            
            // ONLY if distinct from removed phases, update largest_df (matching CPU lines 52-53)
            largest_df = df;
            best_grid_idx = i;
        }
    }
    
    // After finding the best candidate, check distinctness against current compsets (matching CPU lines 54-72)
    if (largest_df > minimum_df && best_grid_idx != -1) {
        int final_candidate_phase_id = grid_data->PhaseID_ptr[best_grid_idx];
        int final_candidate_record_index = get_phase_record_index(phase_data, final_candidate_phase_id);
        const PhaseRecord* final_candidate_phase_record = &phase_data->phase_records_array[final_candidate_record_index];
        
        // Check distinctness against current compsets (matching CPU logic lines 62-72)
        for (int cs_idx = 0; cs_idx < current_sys_state->num_compsets; ++cs_idx) {
            if (current_sys_state->compsets[cs_idx].phase_record == nullptr || 
                current_sys_state->phase_amt[cs_idx] < MIN_PHASE_FRACTION/100.0) continue;

            if (current_sys_state->compsets[cs_idx].phase_record == final_candidate_phase_record) {
                // Same phase type, check overall composition (using X, not site fractions)
                bool compositions_distinct = false;
                for (int comp_j = 0; comp_j < spec->num_components; ++comp_j) {
                    double x_grid = grid_data->X_ptr[best_grid_idx * grid_data->num_components_stride_X + comp_j];
                    double x_compset = current_sys_state->compsets[cs_idx].X[comp_j];
                    if (fabs(x_grid - x_compset) > COMP_DIFFERENCE_TOL) {
                        compositions_distinct = true;
                        break;
                    }
                }
                if (!compositions_distinct) {
                    // Not distinct from current phase, reject this candidate
                    *candidate_phase_grid_idx = -1;
                    *candidate_driving_force = 0.0;
                    return false;
                }
            }
        }
        
        // Passed all distinctness checks
        *candidate_phase_grid_idx = best_grid_idx;
        *candidate_driving_force = largest_df;
        return true;
    }
    
    return false;
}

__device__ int get_phase_record_index(const DevicePhaseData* phase_data, int grid_phase_id) {
    if (grid_phase_id < 0 || grid_phase_id > phase_data->max_grid_phase_id) {
        return -1; // Invalid phase ID
    }
    return phase_data->grid_phase_id_to_record_index[grid_phase_id];
}

/**
 * @brief Identifies nearly stable phases not currently in the system.
 * GPU equivalent of add_nearly_stable from eqsolver.pyx.py.
 *
 * @param candidate_phases_to_add_grid_indices Output: Array to be filled with grid indices of nearly stable phases to consider.
 * @param num_candidates_found Output: Number of nearly stable phases found and placed in the output array.
 * @param max_candidates_to_find Max size of the candidate_phases_to_add_grid_indices array.
 * @param current_sys_state Pointer to the current SystemState.
 * @param spec System-wide specification.
 * @param grid_data Pointer to the grid data on the GPU.
 * @param phase_data Pointer to the phase record data on the GPU.
 * @param state_variables_values Current P, T, etc.
 * @param minimum_df Minimum driving force to consider.
 * @return True if any nearly stable phases were identified, false otherwise.
 */
__device__ bool identify_nearly_stable_phases(
    int* candidate_phases_to_add_grid_indices, // Output array
    double* candidate_phases_df,               // Output array for their DFs
    int* num_candidates_found,                 // Output count
    int max_candidates_to_find,
    const SystemState* current_sys_state,
    const SystemSpecification* spec,
    const DeviceGrid* grid_data,
    const DevicePhaseData* phase_data,
    const double* state_variables_values,
    double minimum_df) {

    *num_candidates_found = 0;
    if (grid_data->num_grid_points_total == 0) return false;

    // Calculate driving forces for all points on the grid (can be large)
    // Ideally, process this on the fly or use a shared memory buffer if block-parallel.
    // For a single thread processing one condition, we iterate.
    // double all_driving_forces_on_grid[MAX_GRID_POINTS]; // Problematic for stack
    // Instead, iterate per phase type.

    for (int record_idx = 0; record_idx < phase_data->num_unique_phase_records; ++record_idx) {
        // Check if this phase type (record_idx) is already in current_sys_state
        bool phase_type_entered = false;
        for (int cs_idx = 0; cs_idx < current_sys_state->num_compsets; ++cs_idx) {
             if (current_sys_state->compsets[cs_idx].phase_record == nullptr || current_sys_state->phase_amt[cs_idx] < MIN_PHASE_FRACTION/100.0) continue;
            // Compare by checking if the phase_record pointer matches one in the global array
            const PhaseRecord* pr_in_compset = current_sys_state->compsets[cs_idx].phase_record;
            if (pr_in_compset == &phase_data->phase_records_array[record_idx]) {
                phase_type_entered = true;
                break;
            }
        }
        if (phase_type_entered) continue;

        // This phase type is not in the current set. Find its best point on the grid.
        // record_idx corresponds to grid phase ID in our mapping
        if (record_idx >= grid_data->num_mappable_phases_in_grid) continue; // Phase not in grid map
        int grid_start_idx = grid_data->phase_grid_indices_start[record_idx];
        int grid_stop_idx = grid_data->phase_grid_indices_stop[record_idx];
        int num_points_for_this_phase = grid_stop_idx - grid_start_idx;

        if (num_points_for_this_phase <= 0) continue;

        double largest_df_for_this_phase_type = -1e30;
        int best_grid_idx_for_this_phase_type = -1;

        for (int i = 0; i < num_points_for_this_phase; ++i) {
            int current_grid_point_abs_idx = grid_start_idx + i;
            if (grid_data->PhaseID_ptr[current_grid_point_abs_idx] != record_idx) continue; // Should match if grid map is correct

            double current_potential_energy = 0.0;
            for (int comp_idx = 0; comp_idx < spec->num_components; ++comp_idx) {
                current_potential_energy += grid_data->X_ptr[current_grid_point_abs_idx * grid_data->num_components_stride_X + comp_idx] *
                                            current_sys_state->chemical_potentials[comp_idx];
            }
            double df = current_potential_energy - grid_data->GM_ptr[current_grid_point_abs_idx];

            if (df > largest_df_for_this_phase_type) {
                largest_df_for_this_phase_type = df;
                best_grid_idx_for_this_phase_type = current_grid_point_abs_idx;
            }
        }

        if (largest_df_for_this_phase_type >= minimum_df && best_grid_idx_for_this_phase_type != -1) {
            if (*num_candidates_found < max_candidates_to_find) {
                candidate_phases_to_add_grid_indices[*num_candidates_found] = best_grid_idx_for_this_phase_type;
                candidate_phases_df[*num_candidates_found] = largest_df_for_this_phase_type;
                (*num_candidates_found)++;
            } else {
                // Found more candidates than space, could prioritize by DF later if needed
                break; 
            }
        }
    } // end loop global_pr_idx

    return (*num_candidates_found > 0);
}

// --- Main single-condition solver (moved from previous response, adapted) ---
// Note: Hook functions (pre_solve_hook, post_solve_hook) are implemented in minimizer.h
// Output struct for a single equilibrium calculation
typedef struct EquilibriumResultSingle { // Ensure this is defined (copied from previous prompt)
    double final_chemical_potentials[MAX_COMPONENTS];
    double final_system_gm;
    int num_stable_phases;
    int phase_ids[MAX_PHASES];
    double NP[MAX_PHASES];
    double X_phases[MAX_PHASES * MAX_COMPONENTS];
    double Y_phases[MAX_PHASES * MAX_DOF_PER_PHASE];
    bool converged;
} EquilibriumResultSingle;

// Input struct for a single condition
typedef struct ConditionArgsSingle { // Ensure this is defined
    double state_variables_values[MAX_STATEVARS];
} ConditionArgsSingle;

// Forward declare the InitialPhaseDataSingle struct (matches kernel definition)
typedef struct InitialPhaseDataSingle {
    int phase_indices[MAX_PHASES];
    double phase_amounts[MAX_PHASES];
    double site_fractions[MAX_PHASES * MAX_DOF_PER_PHASE];
    double compositions[MAX_PHASES * MAX_COMPONENTS];
    double chemical_potentials[MAX_COMPONENTS];
    int num_phases;
} InitialPhaseDataSingle;

/**
 * @brief Solves for equilibrium at a single set of conditions.
 * This is the GPU equivalent of the main loop body in _solve_eq_at_conditions.
 * Uses initial phase data from lower_convex_hull results.
 */
__device__ void solve_equilibrium_at_condition(
    int thread_id,
    const SystemSpecification* global_spec_base,
    const ConditionArgsSingle* condition_args, // Contains P, T for this point
    EquilibriumResultSingle* result,
    const DevicePhaseData* phase_data,         // Provides PhaseRecord array
    const InitialPhaseDataSingle* initial_data, // Initial phase data from lower_convex_hull
    const DeviceGrid* grid_data                // Grid data for add_new/nearly_stable
) {
    SystemSpecification current_spec = *global_spec_base; // Local copy of spec

    // 1. Initial setup: Create initial CompositionSets from lower_convex_hull results
    CompositionSet initial_compsets_for_thread[MAX_PHASES];
    int actual_num_initial_compsets = 0;

    // Debug: Initial data verification
    if (thread_id == 0) {
        printf("GPU DEBUG: solve_equilibrium_at_condition - num_phases=%d\n", initial_data->num_phases);
        for (int debug_i = 0; debug_i < initial_data->num_phases && debug_i < 3; ++debug_i) {
            printf("GPU DEBUG: Initial phase %d: idx=%d, amount=%f, threshold=%e\n", 
                   debug_i, initial_data->phase_indices[debug_i], initial_data->phase_amounts[debug_i], MIN_PHASE_FRACTION/100.0);
        }
    }

    // Use data from lower_convex_hull instead of default initialization
    // CRITICAL FIX: Phases are stored contiguously, not by phase ID!
    // phase_indices[i] tells us which phase model/record to use for phase instance i
    for (int i = 0; i < initial_data->num_phases && i < MAX_PHASES; ++i) {
        // CRITICAL FIX: Preserve spec integrity across iterations
        if (current_spec.num_statevars != global_spec_base->num_statevars) {
            if (thread_id == 0) printf("GPU DEBUG: WARNING - num_statevars corrupted from %d to %d, restoring\n", 
                                      global_spec_base->num_statevars, current_spec.num_statevars);
            current_spec.num_statevars = global_spec_base->num_statevars;
        }
        int pr_idx = initial_data->phase_indices[i];  // Which phase model to use
        if (pr_idx < 0 || pr_idx >= phase_data->num_unique_phase_records) {
            if (thread_id == 0) printf("GPU DEBUG: Skipping phase instance %d - invalid model idx=%d\n", i, pr_idx);
            continue;
        }
        
        double phase_amount = initial_data->phase_amounts[i];
        if (phase_amount <= MIN_PHASE_FRACTION/100.0) {
            if (thread_id == 0) printf("GPU DEBUG: Skipping phase %d - amount %f <= threshold %e\n", i, phase_amount, MIN_PHASE_FRACTION/100.0);
            continue; // Skip negligible phases
        }

        initial_compsets_for_thread[actual_num_initial_compsets].phase_record = &phase_data->phase_records_array[pr_idx];
        const PhaseRecord* pr = initial_compsets_for_thread[actual_num_initial_compsets].phase_record;
        if (!pr) continue;

        // Set state variables from condition args
        for (int sv_idx = 0; sv_idx < current_spec.num_statevars; ++sv_idx) {
             if (sv_idx < MAX_STATEVARS)
                initial_compsets_for_thread[actual_num_initial_compsets].dof[sv_idx] = condition_args->state_variables_values[sv_idx];
        }
        
        // Set site fractions from lower_convex_hull results (not default values!)
        for (int sf_idx = 0; sf_idx < pr->phase_dof; ++sf_idx) {
            if (sf_idx < MAX_DOF_PER_PHASE) {
                // CRITICAL FIX: Use current_spec.num_statevars for consistent workspace DOF format
                initial_compsets_for_thread[actual_num_initial_compsets].dof[current_spec.num_statevars + sf_idx] = 
                    initial_data->site_fractions[i * MAX_DOF_PER_PHASE + sf_idx];
            } else {
                // CRITICAL FIX: Use current_spec.num_statevars for consistent workspace DOF format
                initial_compsets_for_thread[actual_num_initial_compsets].dof[current_spec.num_statevars + sf_idx] = 
                    1.0 / (pr->phase_dof > 0 ? pr->phase_dof : 1.0); // Fallback
            }
        }
        
        // Debug: Confirm site fractions are being read correctly
        if (thread_id == 0) {
            printf("[INITIAL] Phase instance %d (using model %d) site fractions from lower_convex_hull:\n", i, pr_idx);
            printf("  Raw site fractions: ");
            for (int sf_idx = 0; sf_idx < pr->phase_dof && sf_idx < 5; ++sf_idx) {
                printf("Y[%d]=%.15e ", sf_idx, initial_data->site_fractions[i * MAX_DOF_PER_PHASE + sf_idx]);
            }
            printf("\n  DOF array after copy: ");
            for (int sf_idx = 0; sf_idx < pr->phase_dof && sf_idx < 5; ++sf_idx) {
                // CRITICAL FIX: Use current_spec.num_statevars for consistent workspace DOF format
                printf("dof[%d]=%.15e ", current_spec.num_statevars + sf_idx,
                       initial_compsets_for_thread[actual_num_initial_compsets].dof[current_spec.num_statevars + sf_idx]);
            }
            printf("\n");
        }
        
        // Set phase amount from lower_convex_hull results (not default values!)
        initial_compsets_for_thread[actual_num_initial_compsets].NP = phase_amount;
        initial_compsets_for_thread[actual_num_initial_compsets].fixed = false;
        initial_compsets_for_thread[actual_num_initial_compsets].init(pr);
        initial_compsets_for_thread[actual_num_initial_compsets].update(
            &initial_compsets_for_thread[actual_num_initial_compsets].dof[current_spec.num_statevars],
            initial_compsets_for_thread[actual_num_initial_compsets].NP,
            initial_compsets_for_thread[actual_num_initial_compsets].dof,
            current_spec.num_statevars);
        actual_num_initial_compsets++;
        
        // Debug: Confirm CompositionSet was created successfully
        if (thread_id == 0) {
            printf("GPU DEBUG: Successfully created CompositionSet %d for phase %d\n", actual_num_initial_compsets-1, i);
        }
    }

    // Debug: Show total number of CompositionSets created
    if (thread_id == 0) {
        printf("GPU DEBUG: Total CompositionSets created: %d\n", actual_num_initial_compsets);
    }

    SystemState current_sys_state;
    current_sys_state.init(&current_spec, initial_compsets_for_thread, actual_num_initial_compsets);
    
    // CRITICAL: Call recompute to ensure phase_compositions are calculated
    current_sys_state.recompute(&current_spec);
    
    // Debug: Verify SystemState initialization
    if (thread_id == 0) {
        printf("GPU DEBUG: SystemState initialized with num_compsets=%d\n", current_sys_state.num_compsets);
        // Check all phases
        for (int i = 0; i < current_sys_state.num_compsets && i < 3; ++i) {
            printf("[INITIAL PHASES] Phase %d:\n", i);
            printf("  Phase amount: %.15e\n", current_sys_state.phase_amt[i]);
            printf("  Phase compositions: [%.15e, %.15e]\n",
                   current_sys_state.phase_compositions[i * MAX_COMPONENTS + 0],
                   current_sys_state.phase_compositions[i * MAX_COMPONENTS + 1]);
            // Also show site fractions
            CompositionSet* cs = &current_sys_state.compsets[i];
            if (cs->phase_record != nullptr) {
                printf("  Site fractions: Y(NB)=%.15e, Y(TI)=%.15e\n",
                       cs->dof[current_spec.num_statevars + 0],
                       cs->dof[current_spec.num_statevars + 1]);
            }
        }
        printf("GPU DEBUG: After recompute - phase_compositions for phase 0: [%.6f, %.6f]\n",
               current_sys_state.phase_compositions[0], current_sys_state.phase_compositions[1]);
    }
    
    // Initialize chemical potentials from lower_convex_hull results
    for (int i = 0; i < current_spec.num_components && i < MAX_COMPONENTS; ++i) {
        current_sys_state.chemical_potentials[i] = initial_data->chemical_potentials[i];
    }

    // 2. Call add_nearly_stable_gpu (equivalent to pyx _solve_eq_at_conditions pre-loop call)
    // SEGMENT 14: ADD NEARLY STABLE PHASES
    if (thread_id == 0) {
        printf("[GPU] SEGMENT 14: Add nearly stable phases\n");
        printf("[GPU]   threshold: -1000 J/mol\n");
        printf("[GPU]   initial_phase_count: %d\n", current_sys_state.num_compsets);
    }
    
    int nearly_stable_candidates_indices[MAX_PHASES]; // Max possible phases to add
    double nearly_stable_candidates_dfs[MAX_PHASES];
    int num_nearly_stable_found = 0;
    identify_nearly_stable_phases(nearly_stable_candidates_indices, nearly_stable_candidates_dfs,
                                  &num_nearly_stable_found, MAX_PHASES,
                                  &current_sys_state, &current_spec, grid_data, phase_data,
                                  condition_args->state_variables_values, -1000.0 /* minimum_df from pyx */);

    for (int i = 0; i < num_nearly_stable_found; ++i) {
        if (current_sys_state.num_compsets >= MAX_PHASES) break; // No space to add
        
        int grid_idx_to_add = nearly_stable_candidates_indices[i];
        int phase_id_from_grid = grid_data->PhaseID_ptr[grid_idx_to_add];
        if (phase_id_from_grid < 0 || phase_id_from_grid >= phase_data->num_unique_phase_records) continue;

        // Check if this phase *type* is already present. If so, might skip or require very distinct composition.
        // For add_nearly_stable, pyx adds it as metastable (NP=0) if phase *type* is unrepresented.
        bool type_already_present = false;
        for(int csj=0; csj < current_sys_state.num_compsets; ++csj) {
            if (current_sys_state.compsets[csj].phase_record == &phase_data->phase_records_array[phase_id_from_grid]) {
                type_already_present = true;
                break;
            }
        }
        if (type_already_present) continue;


        CompositionSet* new_cs = &current_sys_state.compsets[current_sys_state.num_compsets]; // Get next available slot
        new_cs->phase_record = &phase_data->phase_records_array[phase_id_from_grid];
        const PhaseRecord* pr = new_cs->phase_record;

        for (int sv_idx = 0; sv_idx < current_spec.num_statevars; ++sv_idx) {
            new_cs->dof[sv_idx] = condition_args->state_variables_values[sv_idx];
        }
        // Site fracs from grid_data->Y_ptr
        for (int sf_idx = 0; sf_idx < pr->phase_dof; ++sf_idx) {
            if (sf_idx < grid_data->phase_dof_stride_Y) { // Check Y stride
                 // CRITICAL FIX: Use current_spec.num_statevars for consistent workspace DOF format
                 new_cs->dof[current_spec.num_statevars + sf_idx] = grid_data->Y_ptr[grid_idx_to_add * grid_data->phase_dof_stride_Y + sf_idx];
            } else {
                 // CRITICAL FIX: Use current_spec.num_statevars for consistent workspace DOF format
                 new_cs->dof[current_spec.num_statevars + sf_idx] = 1.0 / (pr->phase_dof > 0 ? pr->phase_dof : 1.0); // Fallback
            }
        }
        new_cs->NP = 0.0; // Added as metastable
        new_cs->fixed = false;
        new_cs->init(pr);
        // CRITICAL FIX: Use current_spec.num_statevars for consistent workspace DOF format
        // The GPU uses workspace variables (N,P,T) throughout for consistency with CPU
        new_cs->update(&new_cs->dof[current_spec.num_statevars], new_cs->NP, new_cs->dof, current_spec.num_statevars);
        current_sys_state.cs_states[current_sys_state.num_compsets].init(&current_spec, new_cs); // Init corresponding CompsetState
        current_sys_state.num_compsets++;
    }
    
    if (thread_id == 0) {
        printf("[GPU]   phase_count_after_adding: %d\n", current_sys_state.num_compsets);
    }
    
    // Normalize phase amounts after adding nearly stable phases (matching CPU logic lines 231-235)
    double phase_amt_sum = 0.0;
    for (int i = 0; i < current_sys_state.num_compsets; ++i) {
        phase_amt_sum += current_sys_state.compsets[i].NP;
    }
    
    if (thread_id == 0) {
        printf("[GPU]   phase_amount_sum_before_normalization: %.15e\n", phase_amt_sum);
    }
    
    if (phase_amt_sum > 1e-12) { // Avoid division by zero
        for (int i = 0; i < current_sys_state.num_compsets; ++i) {
            current_sys_state.compsets[i].NP /= phase_amt_sum;
            current_sys_state.phase_amt[i] = current_sys_state.compsets[i].NP;
        }
    }
    
    if (thread_id == 0) {
        printf("[GPU]   normalized_phases: [");
        for (int i = 0; i < current_sys_state.num_compsets; ++i) {
            printf("(phase_%d, %.6f)", i, current_sys_state.compsets[i].NP);
            if (i < current_sys_state.num_compsets - 1) printf(", ");
        }
        printf("]\n");
    }
    
    // CRITICAL FIX: Synchronize phase_amt with NP but don't normalize here
    // The normalization should only happen in minimizer.h recompute() to match CPU
    for (int i = 0; i < current_sys_state.num_compsets; ++i) {
        CompositionSet* compset = &current_sys_state.compsets[i];
        if (compset->phase_record == nullptr) continue;
        
        // Update compset to calculate X (moles of elements per formula unit)
        double current_dof[MAX_STATEVARS + MAX_DOF_PER_PHASE];
        for (int k = 0; k < current_spec.num_statevars; ++k) {
            current_dof[k] = compset->dof[k];
        }
        for (int k = 0; k < compset->phase_record->phase_dof; ++k) {
            current_dof[current_spec.num_statevars + k] = compset->dof[current_spec.num_statevars + k];
        }
        compset->update(&current_dof[current_spec.num_statevars], compset->NP, current_dof, current_spec.num_statevars);
        
        // CRITICAL FIX: Only synchronize phase_amt with NP - no normalization here
        // The solver updates NP but phase_amt might be out of sync
        current_sys_state.phase_amt[i] = current_sys_state.compsets[i].NP;
        
        if (thread_id == 0 && i == 0) {
            printf("GPU DEBUG: synchronized phase_amt[%d]=%f with NP=%f\n", 
                   i, current_sys_state.phase_amt[i], current_sys_state.compsets[i].NP);
        }
    }
    
    // After adding nearly stable, re-initialize free_stable_compset_indices and other counts in SystemState
    // A full re-init of parts of SystemState or a specific update function might be needed.
    // For now, assume recompute() inside run_loop handles this.


    // 3. Iterative solving loop (mimicking pyx _solve_eq_at_conditions structure)
    bool converged = false;
    bool changed_phases_in_iteration;
    int iterations = 0;
    const int MAX_OUTER_ITERATIONS = 10; // from pyx
    
    // Track removed composition sets to prevent oscillation (matching CPU logic)
    CompositionSet removed_compsets[MAX_PHASES];
    int num_removed_compsets = 0;

    while (iterations < MAX_OUTER_ITERATIONS) {
        if (current_sys_state.num_compsets == 0 && current_spec.prescribed_system_amount > 0) {
             // No phases to solve for, but system exists. This is likely an error or unstable state.
             converged = false; // Or handle as an error state specific to the calculation.
             break;
        }
        
        // Save current composition sets before solving (to track any that get removed)
        CompositionSet compsets_before_solve[MAX_PHASES];
        int num_compsets_before = current_sys_state.num_compsets;
        for (int i = 0; i < num_compsets_before; ++i) {
            compsets_before_solve[i] = current_sys_state.compsets[i]; // Simple assignment copy
        }
        
        converged = run_loop(&current_spec, &current_sys_state, 1000);
        
        // Track any phases that were removed during run_loop (matching minimizer's removal tracking)
        for (int before_idx = 0; before_idx < num_compsets_before; ++before_idx) {
            bool still_present = false;
            for (int after_idx = 0; after_idx < current_sys_state.num_compsets; ++after_idx) {
                if (current_sys_state.compsets[after_idx].phase_record == compsets_before_solve[before_idx].phase_record) {
                    // Check if compositions are similar enough to be considered the same phase
                    // Use 10*COMP_DIFFERENCE_TOL for consistency with removed phase distinctness check
                    bool same_composition = true;
                    for (int dof_idx = 0; dof_idx < compsets_before_solve[before_idx].phase_record->phase_dof; ++dof_idx) {
                        if (fabs(current_sys_state.compsets[after_idx].dof[current_spec.num_statevars + dof_idx] - 
                                compsets_before_solve[before_idx].dof[current_spec.num_statevars + dof_idx]) > 10.0 * COMP_DIFFERENCE_TOL) {
                            same_composition = false;
                            break;
                        }
                    }
                    // Also check if phase amount is still significant (not removed to ~0)
                    if (same_composition && current_sys_state.phase_amt[after_idx] > MIN_PHASE_FRACTION/100.0) {
                        still_present = true;
                        break;
                    }
                }
            }
            
            // If this composition set was removed, add it to removed_compsets tracking
            if (!still_present && num_removed_compsets < MAX_PHASES) {
                removed_compsets[num_removed_compsets] = compsets_before_solve[before_idx]; // Simple assignment instead of deep_copy_from
                num_removed_compsets++;
            }
        }

        // SEGMENT 41: PHASE ADDITION - DRIVING FORCE CALCULATION
        if (thread_id == 0) {
            printf("[GPU] SEGMENT 41: Phase addition - driving force calculation\n");
            printf("[GPU]   chemical_potentials: [%.6f, %.6f]\n",
                   current_sys_state.chemical_potentials[0], current_sys_state.chemical_potentials[1]);
        }
        
        int candidate_idx_to_add = -1;
        double candidate_df = 0.0;
        changed_phases_in_iteration = identify_candidate_phase_to_add(
                                        &candidate_idx_to_add, &candidate_df,
                                        &current_sys_state, &current_spec, grid_data, phase_data,
                                        condition_args->state_variables_values,
                                        1e-4 /* minimum_df from pyx */,
                                        removed_compsets, num_removed_compsets);
        
        if (thread_id == 0) {
            printf("[GPU]   max_driving_force: %.15e\n", candidate_df);
            printf("[GPU]   min_driving_force: %.15e\n", -1e30); // hardcoded minimum
        }

        // SEGMENT 42: PHASE ADDITION - DECISION
        if (thread_id == 0) {
            printf("[GPU] SEGMENT 42: Phase addition - decision\n");
            printf("[GPU]   largest_df: %.15e\n", candidate_df);
            printf("[GPU]   minimum_df: %.15e\n", 1e-4);
            printf("[GPU]   will_add_phase: %s\n", changed_phases_in_iteration ? "true" : "false");
        }
        
        if (changed_phases_in_iteration && candidate_idx_to_add != -1) {
            if (current_sys_state.num_compsets < MAX_PHASES) {
                int phase_id_from_grid = grid_data->PhaseID_ptr[candidate_idx_to_add];
                if (phase_id_from_grid < 0 || phase_id_from_grid >= phase_data->num_unique_phase_records) {
                     changed_phases_in_iteration = false; // Invalid candidate
                } else {
                    if (thread_id == 0) {
                        printf("[GPU]   candidate_phase: phase_%d\n", phase_id_from_grid);
                        // Print candidate composition - need to get from grid
                        printf("[GPU]   candidate_composition: [");
                        for (int c = 0; c < current_spec.num_components; ++c) {
                            printf("%.6f", grid_data->X_ptr[candidate_idx_to_add * grid_data->num_components_stride_X + c]);
                            if (c < current_spec.num_components - 1) printf(", ");
                        }
                        printf("]\n");
                    }
                    CompositionSet* new_cs = &current_sys_state.compsets[current_sys_state.num_compsets];
                    new_cs->phase_record = &phase_data->phase_records_array[phase_id_from_grid];
                    const PhaseRecord* pr = new_cs->phase_record;

                    for (int sv_idx = 0; sv_idx < current_spec.num_statevars; ++sv_idx) {
                        new_cs->dof[sv_idx] = condition_args->state_variables_values[sv_idx];
                    }
                                for (int sf_idx = 0; sf_idx < pr->phase_dof; ++sf_idx) {
                         if (sf_idx < grid_data->phase_dof_stride_Y) {
                            // CRITICAL FIX: Use current_spec.num_statevars for consistent workspace DOF format
                            new_cs->dof[current_spec.num_statevars + sf_idx] = grid_data->Y_ptr[candidate_idx_to_add * grid_data->phase_dof_stride_Y + sf_idx];
                         } else {
                            // CRITICAL FIX: Use current_spec.num_statevars for consistent workspace DOF format
                            new_cs->dof[current_spec.num_statevars + sf_idx] = 1.0 / (pr->phase_dof > 0 ? pr->phase_dof : 1.0);
                         }
                    }
                    new_cs->NP = 1e-6; // Small amount for newly added phase (from pyx)
                    new_cs->fixed = false;
                    new_cs->init(pr);
                    // CRITICAL FIX: Use current_spec.num_statevars for consistent workspace DOF format
        // The GPU uses workspace variables (N,P,T) throughout for consistency with CPU
        new_cs->update(&new_cs->dof[current_spec.num_statevars], new_cs->NP, new_cs->dof, current_spec.num_statevars);
                    current_sys_state.cs_states[current_sys_state.num_compsets].init(&current_spec, new_cs);
                    current_sys_state.num_compsets++;
                    // After adding, SystemState's internal counts like num_free_stable_compsets need update.
                    // A call to a lightweight SystemState update function or manual update is needed here.
                    // For now, assume recompute() at start of run_loop handles this.
                }
            } else {
                changed_phases_in_iteration = false; // No space to add
            }
        }
        iterations++;
        if (!changed_phases_in_iteration) {
            break; // No new phases to add, exit outer loop
        }
    } // end while iterations

    // Final solve if phases were changed in the last iteration
    if (changed_phases_in_iteration) {
         if (current_sys_state.num_compsets > 0) { // Only solve if there are phases
            // Save current composition sets before final solve (to track any that get removed)
            CompositionSet compsets_before_final_solve[MAX_PHASES];
            int num_compsets_before_final = current_sys_state.num_compsets;
            for (int i = 0; i < num_compsets_before_final; ++i) {
                compsets_before_final_solve[i] = current_sys_state.compsets[i]; // Simple assignment copy
            }
            
            converged = run_loop(&current_spec, &current_sys_state, 500);
            
            // Track any phases that were removed during final run_loop
            for (int before_idx = 0; before_idx < num_compsets_before_final; ++before_idx) {
                bool still_present = false;
                for (int after_idx = 0; after_idx < current_sys_state.num_compsets; ++after_idx) {
                    if (current_sys_state.compsets[after_idx].phase_record == compsets_before_final_solve[before_idx].phase_record) {
                        // Check if compositions are similar enough to be considered the same phase
                        // Use 10*COMP_DIFFERENCE_TOL for consistency with removed phase distinctness check
                        bool same_composition = true;
                        for (int dof_idx = 0; dof_idx < compsets_before_final_solve[before_idx].phase_record->phase_dof; ++dof_idx) {
                            if (fabs(current_sys_state.compsets[after_idx].dof[current_spec.num_statevars + dof_idx] - 
                                    compsets_before_final_solve[before_idx].dof[current_spec.num_statevars + dof_idx]) > 10.0 * COMP_DIFFERENCE_TOL) {
                                same_composition = false;
                                break;
                            }
                        }
                        // Also check if phase amount is still significant (not removed to ~0)
                        if (same_composition && current_sys_state.phase_amt[after_idx] > MIN_PHASE_FRACTION/100.0) {
                            still_present = true;
                            break;
                        }
                    }
                }
                
                // If this composition set was removed, add it to removed_compsets tracking
                if (!still_present && num_removed_compsets < MAX_PHASES) {
                    removed_compsets[num_removed_compsets] = compsets_before_final_solve[before_idx]; // Simple assignment
                    num_removed_compsets++;
                }
            }
         } else {
            converged = false; // No phases left, cannot converge to a meaningful state if system amount > 0
         }
    }

    // NOTE: Phase consolidation is already handled in run_loop via remove_and_consolidate_phases
    // The CPU does NOT perform additional phase consolidation after the solver completes
    // We only have consolidation during the solver iterations, not after

    // 4. Store results (copied and adapted from previous `solve_equilibrium_at_condition` body)
    
    // DEBUG: Final values
    if (thread_id == 0) {
        printf("\n[GPU FINAL VALUES]\n");
        printf("  Converged: %s\n", converged ? "true" : "false");
        printf("  Number of stable phases: %d\n", current_sys_state.num_free_stable_compsets);
        for (int i = 0; i < current_sys_state.num_free_stable_compsets; ++i) {
            int idx = current_sys_state.free_stable_compset_indices[i];
            printf("  Phase %d:\n", idx);
            printf("    Amount: %.15e\n", current_sys_state.phase_amt[idx]);
            printf("    X(NB): %.15e\n", current_sys_state.phase_compositions[idx * MAX_COMPONENTS + 0]);
            printf("    X(TI): %.15e\n", current_sys_state.phase_compositions[idx * MAX_COMPONENTS + 1]);
            CompositionSet* cs = &current_sys_state.compsets[idx];
            printf("    Y(NB): %.15e\n", cs->dof[current_spec.num_statevars + 0]);
            printf("    Y(TI): %.15e\n", cs->dof[current_spec.num_statevars + 1]);
        }
        printf("  System mole fractions: X(NB)=%.15e, X(TI)=%.15e\n",
               current_sys_state.mole_fractions[0], current_sys_state.mole_fractions[1]);
    }
    
    result->converged = converged;
    // ... (rest of result population is identical to the previous response's version of this function)
    for (int i = 0; i < current_spec.num_components; ++i) {
        if (i < MAX_COMPONENTS)
            result->final_chemical_potentials[i] = current_sys_state.chemical_potentials[i];
    }

    // SEGMENT 40: FINAL GIBBS ENERGY CALCULATION
    if (thread_id == 0) {
        printf("[GPU] SEGMENT 40: Final Gibbs energy calculation\n");
    }
    
    double final_gm_calc = 0.0;
    int stable_phase_count = 0;
    printf("GPU DEBUG: Collecting stable phases - num_compsets=%d, MIN_PHASE_FRACTION/10=%e\n", 
           current_sys_state.num_compsets, MIN_PHASE_FRACTION / 10.0);
    for (int i = 0; i < current_sys_state.num_compsets; ++i) {
        printf("GPU DEBUG: compset %d - phase_amt=%.10f, threshold=%e\n", 
               i, current_sys_state.phase_amt[i], MIN_PHASE_FRACTION / 10.0);
        if (current_sys_state.phase_amt[i] > MIN_PHASE_FRACTION / 10.0) {
            // Use cs_states[i].energy which is set to pr->formulaobj(compset->dof) in recompute()
            // This is the Gibbs energy per formula unit, which is what the CPU uses
            double phase_contribution = current_sys_state.phase_amt[i] * current_sys_state.cs_states[i].energy;
            final_gm_calc += phase_contribution;
            
            if (thread_id == 0) {
                printf("[GPU]   phase_%d_contribution: NP=%.15e * energy=%.15e = %.15e\n",
                       i, current_sys_state.phase_amt[i], current_sys_state.cs_states[i].energy,
                       phase_contribution);
            }
            
            if (stable_phase_count < MAX_PHASES) {
                result->phase_ids[stable_phase_count] = -1;
                const PhaseRecord* pr_stable = current_sys_state.compsets[i].phase_record;
                if (pr_stable != nullptr) {
                    for (int pr_glob_idx = 0; pr_glob_idx < phase_data->num_unique_phase_records; ++pr_glob_idx) {
                        if (pr_stable == &phase_data->phase_records_array[pr_glob_idx]) {
                            result->phase_ids[stable_phase_count] = pr_glob_idx;
                            break;
                        }
                    }
                }
                result->NP[stable_phase_count] = current_sys_state.phase_amt[i];
                double sum_moles_in_phase_formula = 0.0;
                for (int c = 0; c < current_spec.num_components; ++c) {
                     if (c < MAX_COMPONENTS)
                        sum_moles_in_phase_formula += current_sys_state.phase_compositions[i * current_spec.num_components + c];
                }
                if (fabs(sum_moles_in_phase_formula) < 1e-12) sum_moles_in_phase_formula = 1.0;
                for (int c = 0; c < current_spec.num_components; ++c) {
                    if (stable_phase_count * MAX_COMPONENTS + c < MAX_PHASES * MAX_COMPONENTS && c < MAX_COMPONENTS) {
                        result->X_phases[stable_phase_count * MAX_COMPONENTS + c] =
                            current_sys_state.phase_compositions[i * current_spec.num_components + c] / sum_moles_in_phase_formula;
                    }
                }
                if (current_sys_state.compsets[i].phase_record) {
                    const PhaseRecord* pr = current_sys_state.compsets[i].phase_record;
                    
                    if (thread_id == 0) {
                        printf("[GPU]   phase_%d_Y: [", i);
                    }
                    
                    for (int sf = 0; sf < pr->phase_dof; ++sf) {
                        if (stable_phase_count * MAX_DOF_PER_PHASE + sf < MAX_PHASES * MAX_DOF_PER_PHASE && sf < MAX_DOF_PER_PHASE) {
                            result->Y_phases[stable_phase_count * MAX_DOF_PER_PHASE + sf] =
                                current_sys_state.compsets[i].dof[current_spec.num_statevars + sf];
                            
                            if (thread_id == 0) {
                                printf("%.6f", current_sys_state.compsets[i].dof[current_spec.num_statevars + sf]);
                                if (sf < pr->phase_dof - 1) printf(", ");
                            }
                        }
                    }
                    
                    if (thread_id == 0) {
                        printf("]\n");
                        printf("[GPU]   phase_%d_X: [", i);
                        for (int c = 0; c < current_spec.num_components; ++c) {
                            printf("%.6f", result->X_phases[stable_phase_count * MAX_COMPONENTS + c]);
                            if (c < current_spec.num_components - 1) printf(", ");
                        }
                        printf("]\n");
                    }
                }
                stable_phase_count++;
            }
        }
    }
    result->final_system_gm = final_gm_calc;
    result->num_stable_phases = stable_phase_count;
    
    if (thread_id == 0) {
        printf("[GPU]   final_GM: %.15e\n", final_gm_calc);
    }
    
    printf("GPU DEBUG: Final result assembly - stable_phase_count=%d\n", stable_phase_count);
    for (int i = 0; i < stable_phase_count; ++i) {
        printf("GPU DEBUG: result->NP[%d] = %.10f\n", i, result->NP[i]);
    }
    
    for (int i = stable_phase_count; i < MAX_PHASES; ++i) {
        result->phase_ids[i] = -1;
        result->NP[i] = 0.0;
        for (int c = 0; c < MAX_COMPONENTS; ++c) {
             if (i * MAX_COMPONENTS + c < MAX_PHASES * MAX_COMPONENTS) result->X_phases[i * MAX_COMPONENTS + c] = 0.0;
        }
        for (int sf = 0; sf < MAX_DOF_PER_PHASE; ++sf) {
            if (i * MAX_DOF_PER_PHASE + sf < MAX_PHASES * MAX_DOF_PER_PHASE) result->Y_phases[i * MAX_DOF_PER_PHASE + sf] = 0.0;
        }
    }
}


#endif // EQSOLVER_H
#define OPENCL_1_2_API_UNAVAILABLE
///@cond INTERNAL
/**
 * @file Ctrl_FPGA.c
 * @brief Source code for FPGA backend.
 *
 * @copyright This software is part of the Controller project by Trasgo Group, UVa.
 * The relevant license, warranty and copyright notice is available in the Controller project repository.
 */

#include <dirent.h> // For opening directories
#include <limits.h> // For PATH_MAX
#include <ctype.h>  // For isalnum(), isprint()

#include "Architectures/FPGA/Ctrl_FPGA.h"
#include "Core/Ctrl_Core.h"

#define CTRL_FPGA_MAX_KERNEL_FILES 256

/**
 * Head of the kernel params linked list.
 */
Ctrl_FPGA_KernelParams FPGA_initial_kp = CTRL_FPGA_KERNELPARAMS_NULL;

/**
 * Type id for the next FPGA ctrl.
 */
int next_fpga_id = 0;

/**
 * Global number of kernel files (.aocx) in the kernel path directory.
 *
 * Used as second dimension of pp_fpga_programs (@see pp_fpga_programs).
 */
int n_kernel_files = 0;

/**
 * Global matrix for the built OpenCL kernel programs.
 *
 * Sizes are pp_fpga_programs[n_fpga_ctrl][n_kernel_files]
 */
cl_program **pp_fpga_programs = NULL;

/*************************************************************
 ******** Prototypes of private functions ********************
 *************************************************************/

/**
 * Get the paths for all the kernel files (with .aocx extension) inside the specified FPGA kernels path.
 *
 * @param[in] dir_path The FPGA kernels path.
 * @param[out] kernel_files Buffer of kernel paths containing all the kernel files in \p dir_path.
 * @param[out] count The number of kernel files in \p dir_path.
 */
void Ctrl_FPGA_GetKernelFiles(const char *dir_path, char *kernel_files[CTRL_FPGA_MAX_KERNEL_FILES], int *count);

/**
 * Get the kernel names for a given FPGA kernel cl_program or binary (given its path), as
 * semicolon separated values.
 *
 * If the OpenCL runtime version is >= 1.2 and the cl_program is not NULL, the \p program will be used
 * and \p kernel_path will be ignored. Otherwise, \p kernel_path and \p program will be ignored.
 * If both arguments are NULL, the function returns NULL.
 *
 * The result of this function must be freed later.
 *
 * @param p_ctrl Pointer to the ctrl that will be attached to the kernels we want to get the name of.
 * @param program Pointer to the cl_program to extract the kernel names from (optionally NULL).
 * @param kernel_path Path of the kernel binary file to extract the kernel names from (optionally NULL).
 */
char *Ctrl_FPGA_GetKernelNames(Ctrl_FPGA *p_ctrl, cl_program *program, char *kernel_path);

/**
 * Build the cl_program objects, and create their cl_kernel objects, from the specified kernel (binaries)
 * paths, and add them to the FPGA ctrl.
 *
 * This function allocates \p pp_fpga_programs.
 *
 * @param p_ctrl Pointer to the ctrl attached to the kernels.
 * @param kernel_files Paths to the kernel files to build and extract the kernels from.
 * @param n_kernel_files Number of different paths in \p kernel_files. Shadows the global \p n_kernel_files
 * variable (@see n_kernel_files).
 */
void Ctrl_FPGA_ExtractKernels(Ctrl_FPGA *p_ctrl, char *kernel_files[CTRL_FPGA_MAX_KERNEL_FILES], int n_kernel_files);

/**
 * Initializate a \e Ctrl_FPGA_Tile.
 *
 * @param p_ctrl Pointer to the ctrl attached to the tile and to be updated of the initialization.
 * @param p_task Pointer to the task containing the HitTile that contains the \e Ctrl_FPGA_Tile to be
 * initialized.
 */
void Ctrl_FPGA_InitTile(Ctrl_FPGA *p_ctrl, Ctrl_Task *p_task);

/**
 * Waits for all the work from \p p_ctrl related to \p p_tile_data .
 *
 * @param p_ctrl Pointer to the ctrl attached to the tile.
 * @param p_tile_data Pointer to the ctrl tile.
 *
 * @see Ctrl_FPGA_EvalTaskWaitTile, Ctrl_FPGA_EvalTaskGlobalSync
 */
void Ctrl_FPGA_WaitTileInner(Ctrl_FPGA *p_ctrl, Ctrl_Tile *p_tile_data);

/**
 * Perform memory transfer from host to device.
 *
 * @param p_ctrl Pointer to the ctrl attached to the tile to be moved.
 * @param p_tile Pointer to the task containing the tile to be moved.
 *
 * @see Ctrl_FPGA_EvalTaskMoveTo
 */
void Ctrl_FPGA_EvalTaskMoveToInner(Ctrl_FPGA *p_ctrl, HitTile *p_tile);

/**
 * Perform memory transfer from host to device.
 *
 * @param p_task Task containing the tile to be moved.
 * @param p_ctrl Ctrl responsible for the task.
 *
 * @see Ctrl_FPGA_EvalTaskMoveTo
 */
void Ctrl_FPGA_ExecTaskMoveTo(Ctrl_Task *p_task, Ctrl_FPGA *p_ctrl);

/**
 * Perform memory transfer from device to host.
 *
 * @param p_ctrl Pointer to the ctrl attached to the tile to be moved.
 * @param p_tile Pointer to the task containing the tile to be moved.
 *
 * @see Ctrl_FPGA_EvalTaskMoveFrom
 */
void Ctrl_FPGA_EvalTaskMoveFromInner(Ctrl_FPGA *p_ctrl, HitTile *p_tile);

/**
 * Perform memory transfer from device to host.
 *
 * @param p_task Task containing the tile to be moved.
 * @param p_ctrl Ctrl responsible for the task.
 *
 * @see Ctrl_FPGA_EvalTaskMoveFrom
 */
void Ctrl_FPGA_ExecTaskMoveFrom(Ctrl_Task *p_task, Ctrl_FPGA *p_ctrl);

/**
 * Get \p qid th driver queue used by \p p_ctrl
 * Order of qid is htd, dth, kernels.
 *
 * @param p_ctrl Ctrl to get the queues from.
 * @param qid Pointer to the driver queues used by this ctrl
 * @return Queue \p qid of ctrl \p p_ctrl
 *
 * @pre \p qid must be between 0 and the amount of queues of \p p_ctrl
 * @see Ctrl_FPGA_GetNumQueues
 */
cl_command_queue Ctrl_FPGA_GetCmdQueueById(Ctrl_FPGA *p_ctrl, int qid);

/*************************************************************
 ******** Prototypes of tasks' evaluation functions **********
 *************************************************************/

/**
 * Destroy a FPGA ctrl.
 *
 * @param p_ctrl Ctrl to be destroyed.
 * @param p_task Task with info for cleanup
 */
void Ctrl_FPGA_Destroy(Ctrl_FPGA *p_ctrl, Ctrl_Task *p_task);

/**
 * Evaluation of kernel launch.
 *
 * @param p_ctrl Ctrl in charge of task.
 * @param p_task Task to be evaluated.
 *
 * @see Ctrl_FPGA_EvalTask, Ctrl_Launch
 */
void Ctrl_FPGA_EvalTaskKernelLaunch(Ctrl_FPGA *p_ctrl, Ctrl_Task *p_task);

/**
 * Evaluation of global sync. Waits for all work related to any tile attached to this ctrl.
 *
 * @param p_ctrl Ctrl in charge of task.
 * @param p_task Task to be evaluated.
 *
 * @see Ctrl_FPGA_EvalTask, Ctrl_GlobalSync
 */
void Ctrl_FPGA_EvalTaskGlobalSync(Ctrl_FPGA *p_ctrl, Ctrl_Task *p_task);

/**
 * Evaluation of allocation of tiles.
 *
 * @param p_ctrl Ctrl in charge of task.
 * @param p_task Task to be evaluated.
 *
 * @see Ctrl_FPGA_EvalTask, Ctrl_Alloc
 */
void Ctrl_FPGA_EvalTaskAllocTile(Ctrl_FPGA *p_ctrl, Ctrl_Task *p_task);

/**
 * Evaluation of subselecting tiles.
 *
 * @param p_ctrl: Ctrl in charge of task.
 * @param p_task: task to be evaluated.
 *
 * @see Ctrl_FPGA_EvalTask, Ctrl_Select
 */
void Ctrl_FPGA_EvalTaskSelectTile(Ctrl_FPGA *p_ctrl, Ctrl_Task *p_task);

/**
 * Evaluation of freeing of tiles.
 *
 * @param p_ctrl Ctrl in charge of task.
 * @param p_task Task to be evaluated.
 *
 * @see Ctrl_FPGA_EvalTask, Ctrl_Free
 */
void Ctrl_FPGA_EvalTaskFreeTile(Ctrl_FPGA *p_ctrl, Ctrl_Task *p_task);

/**
 * Evaluation of comunication of tile from host to device.
 *
 * This function checks state of tile and, if comunication is necesary calls to \e Ctrl_FPGA_EvalTaskMoveToInner.
 *
 * @param p_ctrl Ctrl in charge of task.
 * @param p_task Task to be evaluated.
 *
 * @see Ctrl_FPGA_EvalTask, Ctrl_FPGA_EvalTaskMoveToInner, Ctrl_MoveTo
 */
void Ctrl_FPGA_EvalTaskMoveTo(Ctrl_FPGA *p_ctrl, Ctrl_Task *p_task);

/**
 * Evaluation of comunication of tile from host to device.
 *
 * This function checks state of tile and, if comunication is necesary calls to \e Ctrl_FPGA_EvalTaskMoveToInner.
 *
 * @param p_ctrl Ctrl in charge of task.
 * @param p_task Task to be evaluated.
 *
 * @see Ctrl_FPGA_EvalTask, Ctrl_FPGA_EvalTaskMoveToInner, Ctrl_MoveTo
 */
void Ctrl_FPGA_EvalTaskMoveFrom(Ctrl_FPGA *p_ctrl, Ctrl_Task *p_task);

/**
 * Evaluation of wait. Waits for all the work related to the tile specified in \p p_task .
 *
 * @param p_ctrl Ctrl in charge of task.
 * @param p_task Task to be evaluated.
 *
 * @see Ctrl_FPGA_EvalTask, Ctrl_WaitTile
 */
void Ctrl_FPGA_EvalTaskWaitTile(Ctrl_FPGA *p_ctrl, Ctrl_Task *p_task);

/**
 * Evaluation of change of dependance mode.
 *
 * @param p_ctrl Ctrl in charge of task.
 * @param p_task Task to be evaluated.
 */
void Ctrl_FPGA_EvalTaskSetDependanceMode(Ctrl_FPGA *p_ctrl, Ctrl_Task *p_task);

/********************************************
 ******** FPGA Controller functions *********
 ********************************************/

void Ctrl_FPGA_GetKernelFiles(const char *dir_path, char *kernel_files[CTRL_FPGA_MAX_KERNEL_FILES], int *count) {
	DIR           *dir;
	struct dirent *entry;
	*count = 0;

	dir = opendir(dir_path);
	if (dir == NULL) {
		fprintf(stderr, "[Ctrl_FPGA] Error: Invalid kernel directory provided.\n");
		exit(EXIT_FAILURE);
	}

	while ((entry = readdir(dir)) != NULL) {
		// Check if the file ends with ".aocx"
		if (strstr(entry->d_name, ".aocx\0") != NULL) {
			if (*count < CTRL_FPGA_MAX_KERNEL_FILES) {
				// Allocate space for the file path
				kernel_files[*count] = malloc(PATH_MAX);
				if (kernel_files[*count] == NULL) {
					fprintf(stderr, "[Ctrl_FPGA] Internal Error: Could not allocate buffer for kernel file path.\n");
					exit(EXIT_FAILURE);
				}

				// Construct the full path
				snprintf(kernel_files[*count], PATH_MAX, "%s%s", dir_path, entry->d_name);
				(*count)++;
			} else {
				fprintf(stderr, "[Ctrl_FPGA] Warning: Found more than %d kernels in the kernel path. Some of them will be ignored.\n",
						CTRL_FPGA_MAX_KERNEL_FILES);
				fflush(stderr);
				break;
			}
		}
	}

	closedir(dir);

	if (n_kernel_files == 0) {
		fprintf(stderr, "[Ctrl_FPGA] Error: no kernel files found in the specified directory (%s/).\n", Ctrl_FPGA_kernels_path);
		exit(EXIT_FAILURE);
	}
}

// NOTE: This function is called multiple times with the same files.
// It could be optimized by hashing the names somewhere. However, it is not critical,
// as all calls happen only at ctrl creation time.
char *Ctrl_FPGA_GetKernelNames(Ctrl_FPGA *p_ctrl, cl_program *program, char *kernel_path) {
	if (program == NULL && kernel_path == NULL)
		return NULL;

	char *kernel_names;
	if (program != NULL && clGetVersion(p_ctrl->device_id) >= 12) {
		/*
		 * This is the intended version of extracting the kernel names, using OpenCL 1.2.0 API.
		 * However, not all Intel FPGA SDK for OpenCL installations seem to be OpenCL 1.2.0-compliant.
		 */
		size_t kernel_names_len;
		OPENCL_ASSERT_OP(clGetProgramInfo(*program, CL_PROGRAM_KERNEL_NAMES, 0, NULL, &kernel_names_len));
		kernel_names = (char *)malloc(kernel_names_len * sizeof(char));
		OPENCL_ASSERT_OP(clGetProgramInfo(*program, CL_PROGRAM_KERNEL_NAMES, kernel_names_len, (void *)kernel_names, NULL));
	} else {
		/*
		 * This basically implements the C code that produces the same result as the following
		 * unix commands:
		 * `head -c $((16*1024)) *.aocx | strings -n 26 | grep ^ctrl_kernel_fpga_FPGA_[^\.]*$ | awk '!_[$0]++'`
		 */
		const int CTRL_FPGA_AOCX_MAX_READ_SIZE   = 16 * 1024;
		const int CTRL_FPGA_MAX_KERNELS_PER_FILE = 256;
		const int CTRL_FPGA_MAX_KERNEL_NAME_LEN  = 256;

		FILE *kernel = fopen(kernel_path, "rb");

		// We just read the first 16 KiB, as that seems to be enough in the .aocx files
		// to find the occurences of all the kernels' names.
		char buffer[CTRL_FPGA_AOCX_MAX_READ_SIZE + 1];
		fread(buffer, 4096, (CTRL_FPGA_AOCX_MAX_READ_SIZE + 4095) / 4096, kernel); // `head`
		fclose(kernel);

		// Allocate memory for all the kernel names, as semicolon-separated values
		kernel_names            = (char *)malloc(CTRL_FPGA_MAX_KERNELS_PER_FILE *
												 (CTRL_FPGA_MAX_KERNEL_NAME_LEN + 1) * sizeof(char));
		kernel_names[0]         = '\0';
		int kernel_names_offset = 0; // Offset for the beginning of the next name

		// Iterate over the read file contents and find valid kernel names
		int   nstrings = 0;
		char *start    = buffer;
		char *end      = buffer;
		while (end < buffer + CTRL_FPGA_AOCX_MAX_READ_SIZE) {
			// Check the byte is a valid character: [a-zA-Z0-9_]
			if (isalnum(*end) || *end == '_') { // `strings`
				start = end++;

				// Read until next invalid character or delimiter
				while ((isalnum(*end) || *end == '_') && end < buffer + CTRL_FPGA_AOCX_MAX_READ_SIZE) {
					end++;
				}
				*end    = '\0'; // Probably unneeded, but good for testing/debugging
				int len = end - start;

				// Check if the read string is a kernel name
				if (len > 26) { // 26 == strlen("ctrl_kernel_fpga_FPGA_TASK")
					if (nstrings > CTRL_FPGA_MAX_KERNELS_PER_FILE) {
						fprintf(stderr, "[Ctrl_FPGA] Error: The maximum allowed of %d kernels per FPGA "
										"kernel file was exceeded.\n",
								CTRL_FPGA_MAX_KERNELS_PER_FILE);
						exit(EXIT_FAILURE);
					}
					if (len > CTRL_FPGA_MAX_KERNEL_NAME_LEN) {
						if (!strncmp(start, "ctrl_kernel_fpga_FPGA_", 11)) { // 11 == strlen("ctrl_kernel"); less comparisons
							fprintf(stderr, "[Ctrl_FPGA] Error: The maximum allowed kernel name length of %d "
											"characters was exceeded (name length: %d for %s).\n",
									CTRL_FPGA_MAX_KERNEL_NAME_LEN, len, start);
							exit(EXIT_FAILURE);
						}
						continue;
					}

					// Check the found string is a kernel name
					if (!strncmp(start, "ctrl_kernel_fpga_FPGA_", 11)) { // `grep`
						// Check the kernel name has not been already added
						bool new_name = true;
						// Iterate over all the previous names (extracted using strtok)
						if (nstrings > 0) {
							char *name = strtok(kernel_names, ";");
							while (name != NULL) {
								if (name != kernel_names)
									name[-1] = ';'; // Restore the semicolons for the following iterations
								if (new_name && !strcmp(start, name)) {
									new_name = false;
								}

								name = strtok(NULL, ";");
							}
							kernel_names[kernel_names_offset - 1] = ';'; // Restore the semicolon of the last item
						}
						if (new_name) {
							memcpy(kernel_names + kernel_names_offset, start, len);
							kernel_names_offset += len + 1;
							kernel_names[kernel_names_offset - 1] = ';';
							kernel_names[kernel_names_offset]     = '\0';
							nstrings++;
						}
					}
				}
				end++;
			} else {
				end++;
			}
		}
		// Remove trailing semicolon
		if (kernel_names_offset > 0) // To avoid a compilation warning
			kernel_names[kernel_names_offset - 1] = '\0';
	}

	return kernel_names;
}

void Ctrl_FPGA_ExtractKernels(Ctrl_FPGA *p_ctrl, char *kernel_files[CTRL_FPGA_MAX_KERNEL_FILES], int n_kernel_files) {
	cl_int err;

	// Allocate memory in global buffer for the OpenCL program
	pp_fpga_programs[p_ctrl->type_id] = (cl_program *)malloc(n_kernel_files * sizeof(cl_program));

	// Build the OpenCL programs
	for (int i = 0; i < n_kernel_files; i++) {
		FILE       *binary_file;
		const char *kernel_path = kernel_files[i];
		if (!(binary_file = fopen(kernel_path, "rb"))) {
			fprintf(stderr, "[Ctrl_FPGA_Create] Kernel file %s not found.\n", kernel_path);
			exit(EXIT_FAILURE);
		}
		fseek(binary_file, 0, SEEK_END);
		size_t         binary_length = ftell(binary_file);
		unsigned char *binary_str    = (unsigned char *)malloc(binary_length * sizeof(unsigned char));
		rewind(binary_file);
		if (!(fread(binary_str, binary_length, 1, binary_file))) {
			fprintf(stderr, "[Ctrl_FPGA_Create] Error reading kernel binary %s.\n", kernel_path);
			exit(EXIT_FAILURE);
		}

		cl_program *p_program = &pp_fpga_programs[p_ctrl->type_id][i];

		*p_program = clCreateProgramWithBinary(p_ctrl->context, 1, &p_ctrl->device_id,
											   (const size_t *)&binary_length,
											   (const unsigned char **)&binary_str, NULL, &err);
		OPENCL_ASSERT_ERROR(err);
		free(binary_str);

		err = clBuildProgram(*p_program, 1, &p_ctrl->device_id, NULL, NULL, NULL);
		if (err == CL_BUILD_PROGRAM_FAILURE) {
			size_t log_size;
			clGetProgramBuildInfo(*p_program, p_ctrl->device_id, CL_PROGRAM_BUILD_LOG, 0, NULL, &log_size);
			char *log = (char *)malloc(log_size);
			clGetProgramBuildInfo(*p_program, p_ctrl->device_id, CL_PROGRAM_BUILD_LOG, log_size, log, NULL);
			fprintf(stderr, "FPGA kernel compilation error:\n\n%s\n", log);
			exit(EXIT_FAILURE);
		}
		OPENCL_ASSERT_ERROR(err);
	}

	for (Ctrl_FPGA_KernelParams *p_curr_kp = FPGA_initial_kp.p_next; p_curr_kp != NULL; p_curr_kp = p_curr_kp->p_next) {
		bool found_kernel = false;
		for (int i = 0; i < n_kernel_files; i++) {
			// Extract kernel names
			char *kernel_names = Ctrl_FPGA_GetKernelNames(p_ctrl, &pp_fpga_programs[p_ctrl->type_id][i], kernel_files[i]);
			#ifdef _CTRL_DEBUG_
			fprintf(stderr, "[Ctrl_FPGA] Info: Found the following kernel names in file %s: %s\n",
					kernel_files[i], kernel_names);
			fflush(stderr);
			#endif // _CTRL_DEBUG_

			// Create kernels and add them to the ctrl
			char *name = strtok(kernel_names, ";");
			while (name != NULL) {
				if (!strcmp(p_curr_kp->p_kernel_name, name)) {
					p_curr_kp->p_kernel[p_ctrl->type_id] = clCreateKernel(pp_fpga_programs[p_ctrl->type_id][i], (const char *)p_curr_kp->p_kernel_name, &err);
					OPENCL_ASSERT_ERROR(err);
					found_kernel = true;
					break;
				}

				name = strtok(NULL, ";");
			}
			free(kernel_names);
		}

		if (!found_kernel) {
			fprintf(stderr, "[Ctrl_FPGA] Error: Kernel was declared, but no implementation found: %s.\n",
					p_curr_kp->p_kernel_name);
			exit(EXIT_FAILURE);
		}
	}
}

void Ctrl_FPGA_Create(Ctrl_FPGA *p_ctrl, Ctrl_Policy policy, char *args) {
	cl_int err;

	p_ctrl->policy           = policy;
	p_ctrl->type_id          = next_fpga_id++;
	int   platform           = atoi(strtok(args, " ")); // Platform used to choose between available FPGAs, or emu.
	int   device             = atoi(strtok(NULL, " "));
	char *streams            = strtok(NULL, " ");
	p_ctrl->n_kernel_streams = streams == NULL ? 1 : atoi(streams);

	if (p_ctrl->n_kernel_streams <= 0) {
		p_ctrl->n_kernel_streams = 1;
		fprintf(stderr, "[Ctrl_FPGA] Warning: Tried to create FPGA Ctrl with less than one queue; defaulting to 1.\n");
		fflush(stderr);
	}

	p_ctrl->p_kernel_driver_streams = (cl_command_queue *)malloc(p_ctrl->n_kernel_streams * sizeof(cl_command_queue));
	p_ctrl->pp_kernel_host_streams  = (Ctrl_TaskQueue **)malloc(p_ctrl->n_kernel_streams * sizeof(Ctrl_TaskQueue *));
	p_ctrl->dependance_mode         = CTRL_MODE_IMPLICIT;

	// Get OpenCL platform id from platform index
	cl_platform_id *p_platform_ids = (cl_platform_id *)malloc((platform + 1) * sizeof(cl_platform_id));
	OPENCL_ASSERT_OP(clGetPlatformIDs(platform + 1, p_platform_ids, NULL));
	p_ctrl->platform_id = p_platform_ids[platform];
	free(p_platform_ids);

	// Get OpenCL device id from device index
	cl_device_id *p_device_ids = (cl_device_id *)malloc((device + 1) * sizeof(cl_device_id));
	OPENCL_ASSERT_OP(clGetDeviceIDs(p_ctrl->platform_id, CL_DEVICE_TYPE_ACCELERATOR, device + 1, p_device_ids, NULL));
	p_ctrl->device_id = p_device_ids[device];
	free(p_device_ids);

	// Create OpenCL context
	cl_context_properties context_properties[] = {CL_CONTEXT_PLATFORM, (cl_context_properties)p_ctrl->platform_id, 0};
	p_ctrl->context                            = clCreateContext(context_properties, 1, &(p_ctrl->device_id), NULL, NULL, &err);
	OPENCL_ASSERT_ERROR(err);

	p_ctrl->queue_properties = 0;
	#ifdef _CTRL_FPGA_PROFILING_
	p_ctrl->queue_properties |= CL_QUEUE_PROFILING_ENABLE;
	#endif

	p_ctrl->p_tile_list_head = NULL;
	p_ctrl->p_tile_list_tail = NULL;

	// Create OpenCL queues for kernel execution
	p_ctrl->htd_driver_stream = clCreateCommandQueue(p_ctrl->context, p_ctrl->device_id, p_ctrl->queue_properties, &err);
	OPENCL_ASSERT_ERROR(err);
	p_ctrl->dth_driver_stream = clCreateCommandQueue(p_ctrl->context, p_ctrl->device_id, p_ctrl->queue_properties, &err);
	OPENCL_ASSERT_ERROR(err);
	p_ctrl->p_htd_host_stream = Ctrl_TaskQueue_Create();
	p_ctrl->p_dth_host_stream = Ctrl_TaskQueue_Create();
	for (int i = 0; i < p_ctrl->n_kernel_streams; i++) {
		p_ctrl->p_kernel_driver_streams[i] = clCreateCommandQueue(p_ctrl->context, p_ctrl->device_id, p_ctrl->queue_properties, &err);
		OPENCL_ASSERT_ERROR(err);
		p_ctrl->pp_kernel_host_streams[i] = Ctrl_TaskQueue_Create();
	}

	// Create events
	p_ctrl->host_seq_event = Ctrl_GenericEvent_Create(CTRL_EVENT_TYPE_CPU, p_ctrl->global_id);
	p_ctrl->dev_seq_event  = CTRL_GENERIC_EVENT_NULL;

	// Extract all aocx in the specified path for FPGA kernels
	char *kernel_files[CTRL_FPGA_MAX_KERNEL_FILES];
	Ctrl_FPGA_GetKernelFiles(Ctrl_FPGA_kernels_path, kernel_files, &n_kernel_files);
	Ctrl_FPGA_ExtractKernels(p_ctrl, kernel_files, n_kernel_files);
	// Free the memory used for the paths:
	for (int i = 0; i < n_kernel_files; i++)
		free(kernel_files[i]);

	#ifdef _CTRL_FPGA_PROFILING_
	p_ctrl->platform = platform;
	p_ctrl->device   = device;

	p_ctrl->profiling_info_start = CL_PROFILING_COMMAND_START;
	p_ctrl->profiling_info_end   = CL_PROFILING_COMMAND_END;

	p_ctrl->profiling_read_events   = (cl_event *)malloc(_FPGA_PROFILING_N_READ_TASKS_ * sizeof(cl_event));
	p_ctrl->profiling_write_events  = (cl_event *)malloc(_FPGA_PROFILING_N_WRITE_TASKS_ * sizeof(cl_event));
	p_ctrl->profiling_kernel_events = (cl_event *)malloc(_FPGA_PROFILING_N_KERNEL_TASKS_ * sizeof(cl_event));

	p_ctrl->i_read_task   = 0;
	p_ctrl->i_write_task  = 0;
	p_ctrl->i_kernel_task = 0;

	p_ctrl->profiling_total      = 0;
	p_ctrl->profiling_sum        = 0;
	p_ctrl->profiling_offloading = 0;
	p_ctrl->profiling_read       = 0;
	p_ctrl->profiling_write      = 0;
	p_ctrl->profiling_kernel     = 0;

	p_ctrl->profiling_start = 0;
	p_ctrl->profiling_end   = 0;

	p_ctrl->has_first_profiling_event = false;

	p_ctrl->last_profiling_event = p_ctrl->default_event;
	OPENCL_ASSERT_OP(clRetainEvent(p_ctrl->last_profiling_event));

	#ifdef _CTRL_FPGA_PROFILING_VERBOSE_
	p_ctrl->profiling_visual_events = (visual_event *)malloc(
		(_FPGA_PROFILING_N_READ_TASKS_ +
		 _FPGA_PROFILING_N_WRITE_TASKS_ +
		 _FPGA_PROFILING_N_KERNEL_TASKS_) *
		sizeof(visual_event));
	p_ctrl->i_visual_task = 0;
	#endif
	#endif // _CTRL_FPGA_PROFILING_
}

void Ctrl_FPGA_EvalTask(Ctrl_FPGA *p_ctrl, Ctrl_Task *p_task) {
	switch (p_task->task_type) {
		case CTRL_TASK_TYPE_KERNEL:
			Ctrl_FPGA_EvalTaskKernelLaunch(p_ctrl, p_task);
			break;
		case CTRL_TASK_TYPE_GLOBALSYNC:
			Ctrl_FPGA_EvalTaskGlobalSync(p_ctrl, p_task);
			break;
		case CTRL_TASK_TYPE_ALLOCTILE:
			Ctrl_FPGA_EvalTaskAllocTile(p_ctrl, p_task);
			break;
		case CTRL_TASK_TYPE_SELECTTILE:
			Ctrl_FPGA_EvalTaskSelectTile(p_ctrl, p_task);
			break;
		case CTRL_TASK_TYPE_FREETILE:
			Ctrl_FPGA_EvalTaskFreeTile(p_ctrl, p_task);
			break;
		case CTRL_TASK_TYPE_MOVETO:
			Ctrl_FPGA_EvalTaskMoveTo(p_ctrl, p_task);
			break;
		case CTRL_TASK_TYPE_MOVEFROM:
			Ctrl_FPGA_EvalTaskMoveFrom(p_ctrl, p_task);
			break;
		case CTRL_TASK_TYPE_WAITTILE:
			Ctrl_FPGA_EvalTaskWaitTile(p_ctrl, p_task);
			break;
		case CTRL_TASK_TYPE_DESTROYCTRL:
			Ctrl_FPGA_Destroy(p_ctrl, p_task);
			break;
		case CTRL_TASK_TYPE_SETDEPENDANCEMODE:
			Ctrl_FPGA_EvalTaskSetDependanceMode(p_ctrl, p_task);
			break;
		default:
			fprintf(stderr, "[Ctrl_FPGA] Unsupported task type:%d.\n", p_task->task_type);
			exit(EXIT_FAILURE);
	}
}

void Ctrl_FPGA_AllocKernel(int n_fpga_ctrls) {
	pp_fpga_programs = (cl_program **)malloc(n_fpga_ctrls * sizeof(cl_program *));
	for (Ctrl_FPGA_KernelParams *p_curr_kp = FPGA_initial_kp.p_next; p_curr_kp != NULL; p_curr_kp = p_curr_kp->p_next) {
		p_curr_kp->p_kernel = (cl_kernel *)malloc(n_fpga_ctrls * sizeof(cl_kernel));
	}
}

void Ctrl_FPGA_ExecTask(Ctrl_Task *p_task, Ctrl_FPGA *p_ctrl) {
	cl_command_queue cmd_queue = Ctrl_FPGA_GetCmdQueueById(p_ctrl, p_task->stream);
	p_task->request.fpga.queue = &cmd_queue;

	switch (p_task->task_type) {
		case CTRL_TASK_TYPE_KERNEL:
			p_task->pfn_kernel_wrapper(p_task->request, p_task->device_id, CTRL_TYPE_FPGA, p_task->threads, p_task->blocksize, p_task->p_arguments);
			Ctrl_GenericEvent_Release(p_task->event);
			break;
		case CTRL_TASK_TYPE_MOVETO:
			Ctrl_FPGA_ExecTaskMoveTo(p_task, p_ctrl);
			Ctrl_GenericEvent_Release(p_task->event);
			break;
		case CTRL_TASK_TYPE_MOVEFROM:
			Ctrl_FPGA_ExecTaskMoveFrom(p_task, p_ctrl);
			Ctrl_GenericEvent_Release(p_task->event);
			break;
		case CTRL_TASK_TYPE_WAITEVENT:
			OPENCL_ASSERT_OP(clEnqueueBarrierWithWaitList(cmd_queue, 1, p_task->event.event.p_event_cl, NULL));
			break;
		default:
			fprintf(stderr, "[Ctrl_FPGA] ExecTask: task type %d should not get here\n", p_task->task_type);
			exit(EXIT_FAILURE);
	}
}

int Ctrl_FPGA_GetNumQueues(Ctrl_FPGA *p_ctrl) {
	return p_ctrl->n_kernel_streams + 2;
}

Ctrl_TaskQueue **Ctrl_FPGA_GetHostQueues(Ctrl_FPGA *p_ctrl, Ctrl_TaskQueue **pp_queues) {
	pp_queues[0] = p_ctrl->p_htd_host_stream;
	pp_queues[1] = p_ctrl->p_dth_host_stream;

	for (int i = 0; i < p_ctrl->n_kernel_streams; i++) {
		pp_queues[i + 2] = p_ctrl->pp_kernel_host_streams[i];
	}

	return &pp_queues[Ctrl_FPGA_GetNumQueues(p_ctrl)];
}

cl_command_queue Ctrl_FPGA_GetCmdQueueById(Ctrl_FPGA *p_ctrl, int qid) {
	if (qid < 0 || qid > Ctrl_FPGA_GetNumQueues(p_ctrl)) {
		fprintf(stderr, "[Ctrl_FPGA_GetCmdQueueById] Invalid qid %d\n", qid);
		exit(EXIT_FAILURE);
	}
	switch (qid) {
		case 0:
			return p_ctrl->htd_driver_stream;
		case 1:
			return p_ctrl->dth_driver_stream;
		default:
			return p_ctrl->p_kernel_driver_streams[qid - 2];
	}
}

void Ctrl_FPGA_GetInfo(Ctrl_FPGA *p_ctrl, Ctrl_Info *p_info) {
	p_info->type = "FPGA";

	size_t platform_name_size;
	OPENCL_ASSERT_OP(clGetPlatformInfo(p_ctrl->platform_id, CL_PLATFORM_NAME, 0, NULL, &platform_name_size));
	char platform_name[platform_name_size];
	OPENCL_ASSERT_OP(clGetPlatformInfo(p_ctrl->platform_id, CL_PLATFORM_NAME, platform_name_size, platform_name, NULL));

	size_t device_name_size;
	OPENCL_ASSERT_OP(clGetDeviceInfo(p_ctrl->device_id, CL_DEVICE_NAME, 0, NULL, &device_name_size));
	char device_name[device_name_size];
	OPENCL_ASSERT_OP(clGetDeviceInfo(p_ctrl->device_id, CL_DEVICE_NAME, device_name_size, device_name, NULL));

	strncpy(p_info->platform_name, platform_name, CTRL_MAX_DEV_NAME - 1);
	strncpy(p_info->device_name, device_name, CTRL_MAX_DEV_NAME - 1);
	p_info->platform_name[255] = '\0';
	p_info->device_name[255]   = '\0';
	p_info->n_kernel_queues    = p_ctrl->n_kernel_streams;
}

void Ctrl_FPGA_CreateTex(Ctrl_FPGA *p_ctrl, HitTile *p_tile, Ctrl_TexDesc tex_desc) {
	#ifdef _CTRL_DEBUG_
	fprintf(stderr, "[Ctrl_FPGA_CreateTex] Warning: not implemented\n");
	fflush(stderr);
	#endif // _CTRL_DEBUG_
}

/*********************************
 ******* Private functions *******
 *********************************/

void Ctrl_FPGA_InitTile(Ctrl_FPGA *p_ctrl, Ctrl_Task *p_task) {
	Ctrl_Tile *p_tile_data = (Ctrl_Tile *)(p_task->p_tile->ext);
	p_tile_data->valid_impls++;

	Ctrl_FPGA_Tile *p_tile_data_impl_fpga               = (Ctrl_FPGA_Tile *)malloc(sizeof(Ctrl_FPGA_Tile));
	p_tile_data->p_impls[p_ctrl->global_id].type        = CTRL_TYPE_FPGA;
	p_tile_data->p_impls[p_ctrl->global_id].tile.p_fpga = p_tile_data_impl_fpga;

	p_tile_data_impl_fpga->p_ctrl = p_ctrl;

	// create node for the the new tile
	Ctrl_Tile_List *p_list_node        = (Ctrl_Tile_List *)malloc(sizeof(Ctrl_Tile_List));
	p_list_node->p_prev                = NULL;
	p_list_node->p_next                = NULL;
	p_list_node->p_tile_ext            = p_tile_data;
	p_tile_data_impl_fpga->p_tile_elem = p_list_node;

	// insert node into the linked list of tiles
	if (p_ctrl->p_tile_list_tail != NULL) {
		p_ctrl->p_tile_list_tail->p_next = p_list_node;
		p_list_node->p_prev              = p_ctrl->p_tile_list_tail;
		p_ctrl->p_tile_list_tail         = p_list_node;
	} else {
		p_ctrl->p_tile_list_head = p_ctrl->p_tile_list_tail = p_list_node;
	}

	// Create events for this tile
	p_tile_data_impl_fpga->host_last_kernel_read_event  = Ctrl_GenericEvent_Create(CTRL_EVENT_TYPE_CPU, p_ctrl->global_id);
	p_tile_data_impl_fpga->host_last_kernel_write_event = Ctrl_GenericEvent_Create(CTRL_EVENT_TYPE_CPU, p_ctrl->global_id);
	p_tile_data_impl_fpga->host_last_dth_event          = Ctrl_GenericEvent_Create(CTRL_EVENT_TYPE_CPU, p_ctrl->global_id);
	p_tile_data_impl_fpga->host_last_htd_event          = Ctrl_GenericEvent_Create(CTRL_EVENT_TYPE_CPU, p_ctrl->global_id);
	p_tile_data_impl_fpga->dev_last_kernel_read_event   = CTRL_GENERIC_EVENT_NULL;
	p_tile_data_impl_fpga->dev_last_kernel_write_event  = CTRL_GENERIC_EVENT_NULL;
	p_tile_data_impl_fpga->dev_last_dth_event           = CTRL_GENERIC_EVENT_NULL;
	p_tile_data_impl_fpga->dev_last_htd_event           = CTRL_GENERIC_EVENT_NULL;

	p_tile_data_impl_fpga->streamid_last_kr = 0;
	p_tile_data_impl_fpga->streamid_last_kw = 0;
}

void Ctrl_FPGA_WaitTileInner(Ctrl_FPGA *p_ctrl, Ctrl_Tile *p_tile_data) {
	Ctrl_FPGA_Tile *p_tile_data_fpga = p_tile_data->p_impls[p_ctrl->global_id].tile.p_fpga;

	// Wait for all work related to this tile to finish
	Ctrl_GenericEvent_Wait(p_tile_data->last_host_read_event);
	Ctrl_GenericEvent_Wait(p_tile_data->last_host_write_event);
	Ctrl_GenericEvent_Wait(p_tile_data_fpga->host_last_kernel_read_event);
	Ctrl_GenericEvent_Wait(p_tile_data_fpga->host_last_kernel_write_event);
	Ctrl_GenericEvent_Wait(p_tile_data_fpga->host_last_dth_event);
	Ctrl_GenericEvent_Wait(p_tile_data_fpga->host_last_htd_event);
	Ctrl_GenericEvent_Wait(p_tile_data_fpga->dev_last_kernel_read_event);
	Ctrl_GenericEvent_Wait(p_tile_data_fpga->dev_last_kernel_write_event);
	Ctrl_GenericEvent_Wait(p_tile_data_fpga->dev_last_dth_event);
	Ctrl_GenericEvent_Wait(p_tile_data_fpga->dev_last_htd_event);

	Ctrl_GenericEvent_Release(p_tile_data_fpga->dev_last_kernel_read_event);
	Ctrl_GenericEvent_Release(p_tile_data_fpga->dev_last_kernel_write_event);
	Ctrl_GenericEvent_Release(p_tile_data_fpga->dev_last_dth_event);
	Ctrl_GenericEvent_Release(p_tile_data_fpga->dev_last_htd_event);

	p_tile_data_fpga->dev_last_kernel_read_event  = CTRL_GENERIC_EVENT_NULL;
	p_tile_data_fpga->dev_last_kernel_write_event = CTRL_GENERIC_EVENT_NULL;
	p_tile_data_fpga->dev_last_dth_event          = CTRL_GENERIC_EVENT_NULL;
	p_tile_data_fpga->dev_last_htd_event          = CTRL_GENERIC_EVENT_NULL;
}

/* Macro to define MoveTo and MoveFrom logic */
#define OpenCL_Move(type)                                                                                                 \
	HitTile flat_tile = *p_tile;                                                                                          \
	hit_tileFlattenDims(&flat_tile);                                                                                      \
                                                                                                                          \
	HitTile *p_parent = flat_tile.ref;                                                                                    \
	size_t   offset   = 0;                                                                                                \
	if (flat_tile.memStatus == HIT_MS_NOT_OWNER) {                                                                        \
		while (p_parent->memStatus == HIT_MS_NOT_OWNER)                                                                   \
			p_parent = p_parent->ref;                                                                                     \
		offset = (((size_t)flat_tile.data) - ((size_t)p_parent->data)) / flat_tile.baseExtent;                            \
	} else {                                                                                                              \
		p_parent = &flat_tile;                                                                                            \
	}                                                                                                                     \
	/* 1D FLATTENED TILE -> CONTIGUOUS MEMORY */                                                                          \
	if (flat_tile.shape.info.sig.numDims == 1) {                                                                          \
		OPENCL_ASSERT_OP(                                                                                                 \
			clEnqueue##type##Buffer(cmd_queue, p_tile_data_fpga->device_data,                                             \
									CL_FALSE, offset * flat_tile.baseExtent,                                              \
									((size_t)(flat_tile.acumCard)) * (flat_tile.baseExtent),                              \
									flat_tile.data, 0, NULL,                                                              \
									p_task->event.event.p_event_cl));                                                     \
	} /* CONTIGUOUS 2D TILES */                                                                                           \
	else if (flat_tile.shape.info.sig.numDims == 2) {                                                                     \
		size_t dev_offset[3] = {                                                                                          \
			(hit_tileDimBegin(flat_tile, 1) - hit_tileDimBegin(*p_parent, 1)) * p_parent->baseExtent,                     \
			hit_tileDimBegin(flat_tile, 0) - hit_tileDimBegin(*p_parent, 0),                                              \
			0};                                                                                                           \
		size_t zero_offset[3] = {0, 0, 0};                                                                                \
		size_t size[3]        = {flat_tile.card[1] * flat_tile.baseExtent, flat_tile.card[0], 1};                         \
		OPENCL_ASSERT_OP(                                                                                                 \
			clEnqueue##type##BufferRect(                                                                                  \
				cmd_queue,                                                                                                \
				p_tile_data_fpga->device_data,                                                                            \
				CL_FALSE, dev_offset, zero_offset, size,                                                                  \
				(p_parent->baseExtent) * p_parent->origAcumCard[1], 0,                                                    \
				(p_parent->baseExtent) * p_parent->origAcumCard[1], 0,                                                    \
				flat_tile.data, 0, NULL,                                                                                  \
				p_task->event.event.p_event_cl));                                                                         \
	} /* CONTIGUOUS 3D TILES */                                                                                           \
	else if (flat_tile.shape.info.sig.numDims == 3) {                                                                     \
		size_t dev_offset[3] = {                                                                                          \
			(hit_tileDimBegin(flat_tile, 2) - hit_tileDimBegin(*p_parent, 2)) * p_parent->baseExtent,                     \
			hit_tileDimBegin(flat_tile, 1) - hit_tileDimBegin(*p_parent, 1),                                              \
			hit_tileDimBegin(flat_tile, 0) - hit_tileDimBegin(*p_parent, 0)};                                             \
		size_t zero_offset[3] = {0, 0, 0};                                                                                \
		size_t size[3]        = {flat_tile.card[2] * flat_tile.baseExtent, flat_tile.card[1], flat_tile.card[0]};         \
		OPENCL_ASSERT_OP(                                                                                                 \
			clEnqueue##type##BufferRect(                                                                                  \
				cmd_queue,                                                                                                \
				p_tile_data_fpga->device_data,                                                                            \
				CL_FALSE, dev_offset, zero_offset, size,                                                                  \
				(p_parent->baseExtent) * p_parent->card[2],                                                               \
				(p_parent->baseExtent) * p_parent->origAcumCard[1],                                                       \
				(p_parent->baseExtent) * p_parent->card[2],                                                               \
				(p_parent->baseExtent) * p_parent->origAcumCard[1],                                                       \
				flat_tile.data, 0, NULL,                                                                                  \
				p_task->event.event.p_event_cl));                                                                         \
	} else {                                                                                                              \
		fprintf(stderr, "Internal Error: Number of dimensions not supported for non-owner tile in MoveTo/MoveFrom: %d\n", \
				flat_tile.shape.info.sig.numDims);                                                                        \
	}

void Ctrl_FPGA_EvalTaskMoveToInner(Ctrl_FPGA *p_ctrl, HitTile *p_tile) {
	Ctrl_Tile      *p_tile_data      = (Ctrl_Tile *)(p_tile->ext);
	Ctrl_Tile_Impl *p_tile_data_impl = &p_tile_data->p_impls[p_ctrl->global_id];
	Ctrl_FPGA_Tile *p_tile_data_fpga = p_tile_data_impl->tile.p_fpga;

	for (int i = 0; i < Ctrl_GetNCtrls(); i++) {
		if (i == p_ctrl->global_id) continue;

		Ctrl_MoveToWait(&p_tile_data->p_impls[i], p_ctrl->p_htd_host_stream);
	}

	Ctrl_GenericEvent_StreamWait(p_tile_data_fpga->host_last_kernel_read_event, p_ctrl->p_htd_host_stream);
	Ctrl_GenericEvent_StreamWait(p_tile_data_fpga->host_last_kernel_write_event, p_ctrl->p_htd_host_stream);
	Ctrl_GenericEvent_StreamWait(p_tile_data->last_host_write_event, p_ctrl->p_htd_host_stream);
	Ctrl_GenericEvent_StreamWait(p_tile_data_fpga->dev_last_kernel_read_event, p_ctrl->p_htd_host_stream);
	Ctrl_GenericEvent_StreamWait(p_tile_data_fpga->dev_last_kernel_write_event, p_ctrl->p_htd_host_stream);

	// Wait for previous task to finish if policy is sync
	Ctrl_SyncWait(p_ctrl->p_htd_host_stream);

	Ctrl_GenericEvent_Release(p_tile_data_fpga->dev_last_htd_event);
	p_tile_data_fpga->dev_last_htd_event = Ctrl_GenericEvent_Create(CTRL_EVENT_TYPE_OPENCL, p_ctrl->global_id);

	Ctrl_Task task = CTRL_TASK_NULL;
	task.task_type = CTRL_TASK_TYPE_MOVETO;
	task.event     = p_tile_data_fpga->dev_last_htd_event;
	task.tile      = *p_tile;
	Ctrl_GenericEvent_Retain(task.event);
	Ctrl_TaskQueue_Push(p_ctrl->p_htd_host_stream, task);
	Ctrl_CpuEvent_Record(&p_tile_data_fpga->host_last_htd_event.event.event_cpu, p_ctrl->p_htd_host_stream);

	if (p_ctrl->policy == CTRL_POLICY_SYNC) {
		Ctrl_CpuEvent_Record(&p_ctrl->host_seq_event.event.event_cpu, p_ctrl->p_htd_host_stream);
		Ctrl_GenericEvent_Release(p_ctrl->dev_seq_event);
		p_ctrl->dev_seq_event = p_tile_data_fpga->dev_last_htd_event;
		Ctrl_GenericEvent_Retain(p_ctrl->dev_seq_event);
	}

	// Update state of the tile
	p_tile_data->host_status        = CTRL_TILE_VALID;
	p_tile_data_impl->device_status = CTRL_TILE_VALID;
}

void Ctrl_FPGA_MoveToWait(Ctrl_FPGA_Tile *p_tile_data, Ctrl_TaskQueue *p_queue) {
	Ctrl_GenericEvent_StreamWait(p_tile_data->host_last_dth_event, p_queue);
	Ctrl_GenericEvent_StreamWait(p_tile_data->dev_last_dth_event, p_queue);
}

void Ctrl_FPGA_ExecTaskMoveTo(Ctrl_Task *p_task, Ctrl_FPGA *p_ctrl) {
	HitTile        *p_tile           = &p_task->tile;
	Ctrl_Tile      *p_tile_data      = (Ctrl_Tile *)p_tile->ext;
	Ctrl_FPGA_Tile *p_tile_data_fpga = p_tile_data->p_impls[p_ctrl->global_id].tile.p_fpga;

	cl_command_queue cmd_queue = p_ctrl->htd_driver_stream;

	// Enqueue the transfer operation
	OpenCL_Move(Write);

	OPENCL_ASSERT_OP(clFlush(cmd_queue));
}

void Ctrl_FPGA_EvalTaskMoveFromInner(Ctrl_FPGA *p_ctrl, HitTile *p_tile) {
	Ctrl_Tile      *p_tile_data      = (Ctrl_Tile *)(p_tile->ext);
	Ctrl_Tile_Impl *p_tile_data_impl = &p_tile_data->p_impls[p_ctrl->global_id];
	Ctrl_FPGA_Tile *p_tile_data_fpga = p_tile_data_impl->tile.p_fpga;

	for (int i = 0; i < Ctrl_GetNCtrls(); i++) {
		if (i == p_ctrl->global_id) continue;

		Ctrl_MoveFromWait(&p_tile_data->p_impls[i], p_ctrl->p_dth_host_stream);
	}

	// Wait for appropiate events
	Ctrl_GenericEvent_StreamWait(p_tile_data_fpga->host_last_kernel_write_event, p_ctrl->p_dth_host_stream);
	Ctrl_GenericEvent_StreamWait(p_tile_data->last_host_read_event, p_ctrl->p_dth_host_stream);
	Ctrl_GenericEvent_StreamWait(p_tile_data->last_host_write_event, p_ctrl->p_dth_host_stream);
	Ctrl_GenericEvent_StreamWait(p_tile_data_fpga->dev_last_kernel_write_event, p_ctrl->p_dth_host_stream);

	// wait for previous task to finish if policy is sync
	Ctrl_SyncWait(p_ctrl->p_dth_host_stream);

	Ctrl_GenericEvent_Release(p_tile_data_fpga->dev_last_dth_event);
	p_tile_data_fpga->dev_last_dth_event = Ctrl_GenericEvent_Create(CTRL_EVENT_TYPE_OPENCL, p_ctrl->global_id);

	Ctrl_Task task = CTRL_TASK_NULL;
	task.task_type = CTRL_TASK_TYPE_MOVEFROM;
	task.event     = p_tile_data_fpga->dev_last_dth_event;
	task.tile      = *p_tile;
	Ctrl_GenericEvent_Retain(task.event);
	Ctrl_TaskQueue_Push(p_ctrl->p_dth_host_stream, task);
	Ctrl_CpuEvent_Record(&p_tile_data_fpga->host_last_dth_event.event.event_cpu, p_ctrl->p_dth_host_stream);

	if (p_ctrl->policy == CTRL_POLICY_SYNC) {
		Ctrl_CpuEvent_Record(&p_ctrl->host_seq_event.event.event_cpu, p_ctrl->p_dth_host_stream);
		Ctrl_GenericEvent_Release(p_ctrl->dev_seq_event);
		p_ctrl->dev_seq_event = p_tile_data_fpga->dev_last_dth_event;
		Ctrl_GenericEvent_Retain(p_ctrl->dev_seq_event);
	}

	// Update state of the tile
	p_tile_data->host_status        = CTRL_TILE_VALID;
	p_tile_data_impl->device_status = CTRL_TILE_VALID;
}

void Ctrl_FPGA_MoveFromWait(Ctrl_FPGA_Tile *p_tile_data, Ctrl_TaskQueue *p_queue) {
	// TODO @sergioalo does this need to wait for dth transfers?
	Ctrl_GenericEvent_StreamWait(p_tile_data->host_last_htd_event, p_queue);
	Ctrl_GenericEvent_StreamWait(p_tile_data->dev_last_htd_event, p_queue);
}

void Ctrl_FPGA_ExecTaskMoveFrom(Ctrl_Task *p_task, Ctrl_FPGA *p_ctrl) {
	HitTile        *p_tile           = &p_task->tile;
	Ctrl_Tile      *p_tile_data      = (Ctrl_Tile *)p_tile->ext;
	Ctrl_FPGA_Tile *p_tile_data_fpga = p_tile_data->p_impls[p_ctrl->global_id].tile.p_fpga;

	cl_command_queue cmd_queue = p_ctrl->dth_driver_stream;

	// Enqueue the transfer operation
	OpenCL_Move(Read);

	OPENCL_ASSERT_OP(clFlush(cmd_queue));
}

#undef OpenCL_Move

/**********************************
 ** TASKS'S EVALUATION FUNCTIONS **
 **********************************/

void Ctrl_FPGA_Destroy(Ctrl_FPGA *p_ctrl, Ctrl_Task *p_task) {
	#ifdef _CTRL_FPGA_PROFILING_
	#ifdef _FPGA_TEST_OUTPUT_
	printf("%d %d\n", p_ctrl->platform, p_ctrl->device);
	printf("%d %d %d %d %d\n", p_ctrl->i_read_task + p_ctrl->i_write_task + p_ctrl->i_kernel_task,
		   p_ctrl->i_kernel_task, p_ctrl->i_read_task + p_ctrl->i_write_task, p_ctrl->i_read_task, p_ctrl->i_write_task);
	#else
	printf("\n ----------------------- ARGS ----------------------- \n");
	printf("\n PLATFORM: %d", p_ctrl->platform);
	printf("\n DEVICE: %d", p_ctrl->device);
	printf("\n TOTAL TASKS: %d", p_ctrl->i_read_task + p_ctrl->i_write_task + p_ctrl->i_kernel_task);
	printf("\n KERNEL TASKS: %d", p_ctrl->i_kernel_task);
	printf("\n OFFLOADING TASKS: %d", p_ctrl->i_read_task + p_ctrl->i_write_task);
	printf("\n READ TASKS: %d", p_ctrl->i_read_task);
	printf("\n WRITE TASKS: %d", p_ctrl->i_write_task);
	if (p_ctrl->policy == CTRL_POLICY_ASYNC) {
		printf("\n POLICY ASYNC");
	} else {
		printf("\n POLICY SYNC");
	}
	printf("\n\n ---------------------------------------------------- \n");
	#endif // _FPGA_TEST_OUTPUT_

	#ifdef _CTRL_FPGA_PROFILING_VERBOSE_
	FILE *f = fopen("visual_profiler_info.txt", "w");

	for (int i = 0; i < p_ctrl->i_visual_task; i++) {
		OPENCL_ASSERT_OP(clGetEventProfilingInfo(p_ctrl->profiling_visual_events[i].event, p_ctrl->profiling_info_start, sizeof(cl_ulong), (void *)(&(p_ctrl->profiling_start)), NULL));
		OPENCL_ASSERT_OP(clGetEventProfilingInfo(p_ctrl->profiling_visual_events[i].event, p_ctrl->profiling_info_end, sizeof(cl_ulong), (void *)(&(p_ctrl->profiling_end)), NULL));

		fprintf(f, "%d; %d; %lu; %lu\n", p_ctrl->profiling_visual_events[i].queue, p_ctrl->profiling_visual_events[i].op, p_ctrl->profiling_start, p_ctrl->profiling_end);
		OPENCL_ASSERT_OP(clReleaseEvent(p_ctrl->profiling_visual_events[i].event));
	}

	fclose(f);
	free(p_ctrl->profiling_visual_events);
	#endif

	for (int i = 0; i < p_ctrl->i_read_task; i++) {
		OPENCL_ASSERT_OP(clGetEventProfilingInfo(p_ctrl->profiling_read_events[i], p_ctrl->profiling_info_start, sizeof(cl_ulong), (void *)(&(p_ctrl->profiling_start)), NULL));
		OPENCL_ASSERT_OP(clGetEventProfilingInfo(p_ctrl->profiling_read_events[i], p_ctrl->profiling_info_end, sizeof(cl_ulong), (void *)(&(p_ctrl->profiling_end)), NULL));

		p_ctrl->profiling_sum += p_ctrl->profiling_end - p_ctrl->profiling_start;
		p_ctrl->profiling_read += p_ctrl->profiling_end - p_ctrl->profiling_start;
		p_ctrl->profiling_offloading += p_ctrl->profiling_end - p_ctrl->profiling_start;

		OPENCL_ASSERT_OP(clReleaseEvent(p_ctrl->profiling_read_events[i]));
	}
	free(p_ctrl->profiling_read_events);

	for (int i = 0; i < p_ctrl->i_write_task; i++) {
		OPENCL_ASSERT_OP(clGetEventProfilingInfo(p_ctrl->profiling_write_events[i], p_ctrl->profiling_info_start, sizeof(cl_ulong), (void *)(&(p_ctrl->profiling_start)), NULL));
		OPENCL_ASSERT_OP(clGetEventProfilingInfo(p_ctrl->profiling_write_events[i], p_ctrl->profiling_info_end, sizeof(cl_ulong), (void *)(&(p_ctrl->profiling_end)), NULL));

		p_ctrl->profiling_sum += p_ctrl->profiling_end - p_ctrl->profiling_start;
		p_ctrl->profiling_write += p_ctrl->profiling_end - p_ctrl->profiling_start;
		p_ctrl->profiling_offloading += p_ctrl->profiling_end - p_ctrl->profiling_start;

		OPENCL_ASSERT_OP(clReleaseEvent(p_ctrl->profiling_write_events[i]));
	}
	free(p_ctrl->profiling_write_events);

	for (int i = 0; i < p_ctrl->i_kernel_task; i++) {
		OPENCL_ASSERT_OP(clGetEventProfilingInfo(p_ctrl->profiling_kernel_events[i], p_ctrl->profiling_info_start, sizeof(cl_ulong), (void *)(&(p_ctrl->profiling_start)), NULL));
		OPENCL_ASSERT_OP(clGetEventProfilingInfo(p_ctrl->profiling_kernel_events[i], p_ctrl->profiling_info_end, sizeof(cl_ulong), (void *)(&(p_ctrl->profiling_end)), NULL));

		p_ctrl->profiling_sum += p_ctrl->profiling_end - p_ctrl->profiling_start;
		p_ctrl->profiling_kernel += p_ctrl->profiling_end - p_ctrl->profiling_start;

		OPENCL_ASSERT_OP(clReleaseEvent(p_ctrl->profiling_kernel_events[i]));
	}
	free(p_ctrl->profiling_kernel_events);

	OPENCL_ASSERT_OP(clGetEventProfilingInfo(p_ctrl->first_profiling_event, p_ctrl->profiling_info_start, sizeof(cl_ulong), (void *)(&(p_ctrl->profiling_start)), NULL));
	OPENCL_ASSERT_OP(clGetEventProfilingInfo(p_ctrl->last_profiling_event, p_ctrl->profiling_info_end, sizeof(cl_ulong), (void *)(&(p_ctrl->profiling_end)), NULL));

	p_ctrl->profiling_total = p_ctrl->profiling_end - p_ctrl->profiling_start;

	OPENCL_ASSERT_OP(clReleaseEvent(p_ctrl->first_profiling_event));
	OPENCL_ASSERT_OP(clReleaseEvent(p_ctrl->last_profiling_event));

	#ifdef _FPGA_TEST_OUTPUT_
	printf("%lf %lf %lf %lf %lf\n", p_ctrl->profiling_total / 1000000.0, p_ctrl->profiling_sum / 1000000.0, p_ctrl->profiling_kernel / 1000000.0, p_ctrl->profiling_offloading / 1000000.0, p_ctrl->profiling_read / 1000000.0, p_ctrl->profiling_write / 1000000.0);
	#else
	printf("\n -------------------- PROFILING --------------------- \n");
	printf("\n Total Time: %.3lf", p_ctrl->profiling_total / 1000000.0);
	printf("\n Acumulate Sum Time: %.3lf", p_ctrl->profiling_sum / 1000000.0);
	printf("\n Kernel Time: %.3lf", p_ctrl->profiling_kernel / 1000000.0);
	printf("\n Offloading Time: %.3lf", p_ctrl->profiling_offloading / 1000000.0);
	printf("\n Read Time: %.3lf", p_ctrl->profiling_read / 1000000.0);
	printf("\n Write Time: %.3lf", p_ctrl->profiling_write / 1000000.0);
	printf("\n\n ---------------------------------------------------- \n");
	#endif // _FPGA_TEST_OUTPUT_
	#endif // _CTRL_FPGA_PROFILING_

	if (p_ctrl->p_tile_list_head != NULL) {
		fprintf(stderr, "Warning: Tiles left attached to ctrl %d\n", p_ctrl->global_id);
		fflush(stderr);
	}

	p_ctrl->p_tile_list_head = NULL;
	p_ctrl->p_tile_list_tail = NULL;

	// 1st fpga ctrl destroys and frees all ocl kernel stuff and global ocl program matrix
	if (p_ctrl->type_id == 0) {
		for (Ctrl_FPGA_KernelParams *p_curr_kp = FPGA_initial_kp.p_next; p_curr_kp != NULL; p_curr_kp = p_curr_kp->p_next) {
			for (int i = 0; i < next_fpga_id; i++) {
				OPENCL_ASSERT_OP(clReleaseKernel(p_curr_kp->p_kernel[i]));
			}
			free(p_curr_kp->p_kernel);
		}
		for (int i = 0; i < next_fpga_id; i++) {
			for (int j = 0; j < n_kernel_files; j++) {
				OPENCL_ASSERT_OP(clReleaseProgram(pp_fpga_programs[i][j]));
			}
			free(pp_fpga_programs[i]);
		}
		free(pp_fpga_programs);
	}

	Ctrl_GenericEvent_Release(p_ctrl->host_seq_event);
	Ctrl_GenericEvent_Release(p_ctrl->dev_seq_event);

	for (int i = 0; i < p_ctrl->n_kernel_streams; i++) {
		OPENCL_ASSERT_OP(clReleaseCommandQueue(p_ctrl->p_kernel_driver_streams[i]));
	}
	OPENCL_ASSERT_OP(clReleaseCommandQueue(p_ctrl->htd_driver_stream));
	OPENCL_ASSERT_OP(clReleaseCommandQueue(p_ctrl->dth_driver_stream));
	OPENCL_ASSERT_OP(clReleaseContext(p_ctrl->context));
	free(p_ctrl->p_kernel_driver_streams);
	free(p_ctrl->pp_kernel_host_streams);
}

void Ctrl_FPGA_EvalTaskGlobalSync(Ctrl_FPGA *p_ctrl, Ctrl_Task *p_task) {
	for (Ctrl_Tile_List *p_aux = p_ctrl->p_tile_list_head; p_aux != NULL; p_aux = p_aux->p_next) {
		Ctrl_FPGA_WaitTileInner(p_ctrl, (Ctrl_Tile *)(p_aux->p_tile_ext));
	}
}

void Ctrl_FPGA_EvalTaskKernelLaunch(Ctrl_FPGA *p_ctrl, Ctrl_Task *p_task) {
	// Check if the specified queue exists:
	if (p_task->stream < 0 || p_task->stream >= p_ctrl->n_kernel_streams) {
		fprintf(stderr, "[Ctrl_FPGA] Internal Error: Tried to execute a task on a nonexistent queue: %d\n", p_task->stream);
		fflush(stderr);
		exit(EXIT_FAILURE);
	}

	Ctrl_TaskQueue *p_host_kernel_queue = p_ctrl->pp_kernel_host_streams[p_task->stream];

	// wait for appropiate events from arguments according to their role
	for (int i = 0; i < p_task->n_arguments; i++) {
		if (p_task->p_roles[i] != KERNEL_INVAL) {
			HitTile        *p_tile           = (HitTile *)(p_task->pp_pointers[i]);
			Ctrl_Tile      *p_tile_data      = (Ctrl_Tile *)(p_tile->ext);
			Ctrl_Tile_Impl *p_tile_data_impl = &p_tile_data->p_impls[p_ctrl->global_id];
			Ctrl_FPGA_Tile *p_tile_data_fpga = p_tile_data_impl->tile.p_fpga;

			if (hit_tileIsNull(*p_tile)) {
				fprintf(stderr, "Warning: Launching task %s, skipping null tile on parameter %d (starting at 0)\n", p_task->p_func_name, i);
				fflush(stderr);
				continue;
			}

			if (p_tile_data_impl->device_status == CTRL_TILE_UNALLOC) {
				fprintf(stderr, "[Ctrl_FPGA] Internal Error: Launching kernel %s with a tile with no device memory as parameter %d (starting at 0)\n", p_task->p_func_name, i);
				fflush(stderr);
				exit(EXIT_FAILURE);
			}

			// if tile's role is IN or IO, is not updated on device and host has memory allocated transfer it
			if (p_task->p_roles[i] != KERNEL_OUT && p_tile_data_impl->device_status == CTRL_TILE_INVALID &&
				p_tile_data->host_status != CTRL_TILE_UNALLOC && p_ctrl->dependance_mode == CTRL_MODE_IMPLICIT) {
				if (p_tile_data->host_status != CTRL_TILE_VALID) {
					for (int j = 0; j < Ctrl_GetNCtrls(); j++) {
						Ctrl_Tile_Impl *p_tile_impl_j = &p_tile_data->p_impls[j];
						if (p_tile_impl_j->device_status == CTRL_TILE_VALID) {
							// TODO @sergioalo if tiles had ptr to associated abstract ctrl normal movefrom could be used and this switch removed
							switch (p_tile_impl_j->type) {
								#ifdef _CTRL_ARCH_CPU_
								case CTRL_TYPE_CPU:
									Ctrl_Cpu_EvalTaskMoveFromInner(p_tile_impl_j->tile.p_cpu->p_ctrl, p_tile);
									break;
								#endif // _CTRL_ARCH_CPU_

								#ifdef _CTRL_ARCH_CUDA_
								case CTRL_TYPE_CUDA:
									Ctrl_Cuda_EvalTaskMoveFromInner(p_tile_impl_j->tile.p_cuda->p_ctrl, p_tile);
									break;
								#endif // _CTRL_ARCH_CUDA_

								#ifdef _CTRL_ARCH_HIP_
								case CTRL_TYPE_HIP:
									Ctrl_Hip_EvalTaskMoveFromInner(p_tile_impl_j->tile.p_hip->p_ctrl, p_tile);
									break;
								#endif // _CTRL_ARCH_HIP_

								#ifdef _CTRL_ARCH_OPENCL_GPU_
								case CTRL_TYPE_OPENCL_GPU:
									Ctrl_OpenCLGpu_EvalTaskMoveFromInner(p_tile_impl_j->tile.p_opencl->p_ctrl, p_tile);
									break;
								#endif // _CTRL_ARCH_OPENCL_GPU_

								#ifdef _CTRL_ARCH_FPGA_
								case CTRL_TYPE_FPGA:
									Ctrl_FPGA_EvalTaskMoveFromInner(p_tile_impl_j->tile.p_fpga->p_ctrl, p_tile);
									break;
								#endif // _CTRL_ARCH_FPGA_
								default:
									break;
							}
							break;
						}
					}
					if (p_tile_data->host_status == CTRL_TILE_INVALID) {
						fprintf(stderr, "[Ctrl_FPGA] Warning: Tile with uninitialized data as input on kernel %s, parameter: %d (starting at 0)\n", p_task->p_func_name, i);
						fflush(stderr);
					}
				}
				Ctrl_FPGA_EvalTaskMoveToInner(p_ctrl, p_tile);
			}

			if (p_tile_data_impl->device_status == CTRL_TILE_INVALID && p_task->p_roles[i] != KERNEL_OUT) {
				fprintf(stderr, "[Ctrl_FPGA] Warning: Tile with uninitialized data as input on kernel %s, parameter: %d (starting at 0)\n", p_task->p_func_name, i);
				fflush(stderr);
			}

			// no need to wait for kw if last kw op was on the same stream
			if (p_tile_data_fpga->streamid_last_kw != p_task->stream) {
				Ctrl_GenericEvent_StreamWait(p_tile_data_fpga->host_last_kernel_write_event, p_host_kernel_queue);
				Ctrl_GenericEvent_StreamWait(p_tile_data_fpga->dev_last_kernel_write_event, p_host_kernel_queue);
			}

			if (p_tile_data->host_status != CTRL_TILE_UNALLOC && !(p_tile_data_impl->device_status == CTRL_TILE_VALID && p_tile_data->host_status == CTRL_TILE_INVALID)) {
				Ctrl_GenericEvent_StreamWait(p_tile_data_fpga->host_last_htd_event, p_host_kernel_queue);
				Ctrl_GenericEvent_StreamWait(p_tile_data_fpga->dev_last_htd_event, p_host_kernel_queue);
			}

			if (p_task->p_roles[i] != KERNEL_IN) {
				// no need to wait for kw if last kw op was on the same stream
				if (p_tile_data_fpga->streamid_last_kw != p_task->stream) {
					Ctrl_GenericEvent_StreamWait(p_tile_data_fpga->host_last_kernel_read_event, p_host_kernel_queue);
					Ctrl_GenericEvent_StreamWait(p_tile_data_fpga->dev_last_kernel_read_event, p_host_kernel_queue);
				}

				if (p_tile_data->host_status != CTRL_TILE_UNALLOC && !(p_tile_data_impl->device_status == CTRL_TILE_VALID && p_tile_data->host_status == CTRL_TILE_INVALID)) {
					Ctrl_GenericEvent_StreamWait(p_tile_data_fpga->host_last_dth_event, p_host_kernel_queue);
					Ctrl_GenericEvent_StreamWait(p_tile_data_fpga->dev_last_dth_event, p_host_kernel_queue);
				}
			}
		}
	}

	Ctrl_SyncWait(p_host_kernel_queue);

	Ctrl_GenericEvent kernel_event = Ctrl_GenericEvent_Create(CTRL_EVENT_TYPE_OPENCL, p_ctrl->global_id);

	// create request with info for kernel execution
	Ctrl_Request request;
	request.fpga.device_id           = &(p_ctrl->device_id);
	request.fpga.p_last_kernel_event = kernel_event.event.p_event_cl;
	request.fpga.n_arguments         = p_task->n_arguments;
	request.fpga.p_roles             = p_task->p_roles;
	request.fpga.p_displacements     = p_task->p_displacements;
	request.fpga.type_id             = p_ctrl->type_id;

	p_task->request = request;
	p_task->event   = kernel_event;
	Ctrl_GenericEvent_Retain(p_task->event);
	Ctrl_TaskQueue_Push(p_host_kernel_queue, *p_task);

	// update events on arguments according to their roles
	for (int i = 0; i < p_task->n_arguments; i++) {
		if (p_task->p_roles[i] != KERNEL_INVAL) {
			HitTile        *p_tile           = (HitTile *)(p_task->pp_pointers[i]);
			Ctrl_Tile      *p_tile_data      = (Ctrl_Tile *)(p_tile->ext);
			Ctrl_Tile_Impl *p_tile_data_impl = &p_tile_data->p_impls[p_ctrl->global_id];
			Ctrl_FPGA_Tile *p_tile_data_fpga = p_tile_data_impl->tile.p_fpga;

			if (p_task->p_roles[i] != KERNEL_IN) {
				if (p_tile_data->host_status == CTRL_TILE_VALID) p_tile_data->host_status = CTRL_TILE_INVALID;
				// invalidate tile on all other devs except this
				for (int j = 0; j < Ctrl_GetNCtrls(); j++) {
					Ctrl_Tile_Impl *p_tile_data_impl_j = &p_tile_data->p_impls[j];
					if (p_tile_data_impl_j->type == CTRL_TYPE_NULL) {
						continue;
					}
					if (p_tile_data_impl_j->device_status == CTRL_TILE_VALID) p_tile_data_impl_j->device_status = CTRL_TILE_INVALID;
				}

				p_tile_data_impl->device_status = CTRL_TILE_VALID;
				Ctrl_CpuEvent_Record(&p_tile_data_fpga->host_last_kernel_write_event.event.event_cpu, p_host_kernel_queue);
				Ctrl_GenericEvent_Release(p_tile_data_fpga->dev_last_kernel_write_event);
				p_tile_data_fpga->dev_last_kernel_write_event = kernel_event;
				Ctrl_GenericEvent_Retain(p_tile_data_fpga->dev_last_kernel_write_event);
				p_tile_data_fpga->streamid_last_kw = p_task->stream;
			}

			if (p_task->p_roles[i] != KERNEL_OUT) {
				Ctrl_CpuEvent_Record(&p_tile_data_fpga->host_last_kernel_read_event.event.event_cpu, p_host_kernel_queue);
				Ctrl_GenericEvent_Release(p_tile_data_fpga->dev_last_kernel_read_event);
				p_tile_data_fpga->dev_last_kernel_read_event = kernel_event;
				Ctrl_GenericEvent_Retain(p_tile_data_fpga->dev_last_kernel_read_event);
				p_tile_data_fpga->streamid_last_kr = p_task->stream;
			}
		}
	}

	if (p_ctrl->policy == CTRL_POLICY_SYNC) {
		Ctrl_CpuEvent_Record(&p_ctrl->host_seq_event.event.event_cpu, p_host_kernel_queue);
		Ctrl_GenericEvent_Release(p_ctrl->dev_seq_event);
		p_ctrl->dev_seq_event = kernel_event;
		Ctrl_GenericEvent_Retain(p_ctrl->dev_seq_event);
	}
	Ctrl_GenericEvent_Release(kernel_event);
}

void Ctrl_FPGA_HostTaskWait(Ctrl_FPGA_Tile *p_tile, char rol, Ctrl_TaskQueue *p_queue) {
	Ctrl_GenericEvent_StreamWait(p_tile->host_last_dth_event, p_queue);
	Ctrl_GenericEvent_StreamWait(p_tile->dev_last_dth_event, p_queue);

	if (rol != KERNEL_IN) {
		Ctrl_GenericEvent_StreamWait(p_tile->host_last_htd_event, p_queue);
		Ctrl_GenericEvent_StreamWait(p_tile->dev_last_htd_event, p_queue);
	}
}

void Ctrl_FPGA_SyncWait(Ctrl_FPGA *p_ctrl, Ctrl_TaskQueue *p_queue) {
	Ctrl_GenericEvent_StreamWait(p_ctrl->host_seq_event, p_queue);
	Ctrl_GenericEvent_StreamWait(p_ctrl->dev_seq_event, p_queue);
}

void Ctrl_FPGA_EvalTaskAllocTile(Ctrl_FPGA *p_ctrl, Ctrl_Task *p_task) {
	cl_int err;

	HitTile        *p_tile           = p_task->p_tile;
	Ctrl_Tile      *p_tile_data      = (Ctrl_Tile *)(p_tile->ext);
	Ctrl_Tile_Impl *p_tile_data_impl = &p_tile_data->p_impls[p_ctrl->global_id];

	if (p_tile_data_impl->type == CTRL_TYPE_NULL)
		Ctrl_FPGA_InitTile(p_ctrl, p_task);

	Ctrl_FPGA_Tile *p_tile_data_fpga = p_tile_data_impl->tile.p_fpga;

	// TODO @sergioalo fpga requires aligned memory, what to do if mem was already allocated by another ctrl?
	if (p_tile_data->host_status == CTRL_TILE_UNALLOC && (p_task->flags & CTRL_MEM_ALLOC_HOST || !(p_task->flags & CTRL_MEM_ALLOC_DEV))) {
		// Allocate host memory
		p_tile_data->pinned      = CTRL_TYPE_NULL;
		p_tile_data->host_status = CTRL_TILE_INVALID;
		posix_memalign(&p_tile->data, AOCL_ALIGNMENT, (size_t)p_tile->acumCard * p_tile->baseExtent);
		p_tile->memPtr = p_tile->data;
	}

	if (p_task->flags & CTRL_MEM_ALLOC_DEV || !(p_task->flags & CTRL_MEM_ALLOC_HOST)) {
		if (p_tile_data_impl->device_status != CTRL_TILE_UNALLOC) {
			fprintf(stderr, "[Ctrl_FPGA] Warning: Device memory already allocated for this tile, ignoring this call.\n");
			fflush(stderr);
			return;
		}
		// Allocate device memory
		p_tile_data_impl->device_status = CTRL_TILE_INVALID;
		p_tile_data_fpga->device_data   = clCreateBuffer(p_ctrl->context, CL_MEM_READ_WRITE, ((size_t)(p_tile->acumCard)) * (p_tile->baseExtent), NULL, &err);
		OPENCL_ASSERT_ERROR(err);
	}
}

void Ctrl_FPGA_EvalTaskSelectTile(Ctrl_FPGA *p_ctrl, Ctrl_Task *p_task) {
	HitTile *p_tile = p_task->p_tile;

	Ctrl_FPGA_InitTile(p_ctrl, p_task);

	HitTile        *p_parent           = p_tile->ref;
	Ctrl_Tile      *p_tile_data        = (Ctrl_Tile *)(p_tile->ext);
	Ctrl_Tile_Impl *p_tile_data_impl   = &p_tile_data->p_impls[p_ctrl->global_id];
	Ctrl_FPGA_Tile *p_tile_data_fpga   = p_tile_data_impl->tile.p_fpga;
	Ctrl_Tile      *p_parent_data      = ((Ctrl_Tile *)(p_parent->ext));
	Ctrl_Tile_Impl *p_parent_data_impl = &p_parent_data->p_impls[p_ctrl->global_id];
	Ctrl_FPGA_Tile *p_parent_data_fpga = p_parent_data_impl->tile.p_fpga;

	if (p_tile->memStatus == HIT_MS_NOT_OWNER) {
		p_tile_data_impl->device_status = p_parent_data_impl->device_status;

		/* Use parent buffers. Offset added inside the kernels (device pointers can't be edited in host scope). */
		p_tile_data_fpga->device_data = p_parent_data_fpga->device_data;
	}
}

void Ctrl_FPGA_EvalTaskFreeTile(Ctrl_FPGA *p_ctrl, Ctrl_Task *p_task) {
	HitTile        *p_tile           = p_task->p_tile;
	Ctrl_Tile      *p_tile_data      = (Ctrl_Tile *)(p_tile->ext);
	Ctrl_Tile_Impl *p_tile_data_impl = &p_tile_data->p_impls[p_ctrl->global_id];
	Ctrl_FPGA_Tile *p_tile_data_fpga = p_tile_data_impl->tile.p_fpga;

	// tile not initialized
	if (p_tile_data_impl->type == CTRL_TYPE_NULL) {
		fprintf(stderr, "[Ctrl_FPGA] Warning: Free from tile not attached to ctrl.\n");
		return;
	}

	p_tile_data->valid_impls--;

	// Wait for all work related to this tile to finish
	Ctrl_FPGA_WaitTileInner(p_ctrl, p_tile_data);

	// destroy events inside the tile
	Ctrl_GenericEvent_Release(p_tile_data_fpga->host_last_kernel_read_event);
	Ctrl_GenericEvent_Release(p_tile_data_fpga->host_last_kernel_write_event);
	Ctrl_GenericEvent_Release(p_tile_data_fpga->host_last_dth_event);
	Ctrl_GenericEvent_Release(p_tile_data_fpga->host_last_htd_event);
	Ctrl_GenericEvent_Release(p_tile_data_fpga->dev_last_kernel_read_event);
	Ctrl_GenericEvent_Release(p_tile_data_fpga->dev_last_kernel_write_event);
	Ctrl_GenericEvent_Release(p_tile_data_fpga->dev_last_dth_event);
	Ctrl_GenericEvent_Release(p_tile_data_fpga->dev_last_htd_event);

	if (p_tile->memStatus == HIT_MS_OWNER) {
		if (p_tile_data_impl->device_status != CTRL_TILE_UNALLOC) {
			OPENCL_ASSERT_OP(clReleaseMemObject(p_tile_data_fpga->device_data));
		}
	}

	// Remove tle from tile linked list
	if (p_tile_data_fpga->p_tile_elem->p_prev != NULL) {
		p_tile_data_fpga->p_tile_elem->p_prev->p_next = p_tile_data_fpga->p_tile_elem->p_next;
	} else {
		p_ctrl->p_tile_list_head = p_tile_data_fpga->p_tile_elem->p_next;
	}

	if (p_tile_data_fpga->p_tile_elem->p_next != NULL) {
		p_tile_data_fpga->p_tile_elem->p_next->p_prev = p_tile_data_fpga->p_tile_elem->p_prev;
	} else {
		p_ctrl->p_tile_list_tail = p_tile_data_fpga->p_tile_elem->p_prev;
	}

	// Clear node fields
	p_tile_data_fpga->p_tile_elem->p_tile_ext = NULL;
	p_tile_data_fpga->p_tile_elem->p_next     = NULL;
	p_tile_data_fpga->p_tile_elem->p_prev     = NULL;

	// Free node
	free(p_tile_data_fpga->p_tile_elem);

	// Clear tile fields
	p_tile_data_fpga->p_ctrl = NULL;

	// Free tile
	free(p_tile_data_fpga);

	// if this was the last ctrl the tile was attached to free the host stuff as well
	if (p_tile_data->valid_impls == 0) {
		Ctrl_FreeHostInner(p_tile);
	}
}

void Ctrl_FPGA_EvalTaskMoveTo(Ctrl_FPGA *p_ctrl, Ctrl_Task *p_task) {
	HitTile        *p_tile           = p_task->p_tile;
	Ctrl_Tile      *p_tile_data      = (Ctrl_Tile *)(p_tile->ext);
	Ctrl_Tile_Impl *p_tile_data_impl = &p_tile_data->p_impls[p_ctrl->global_id];

	if (hit_tileIsNull(*p_tile)) return;

	if (p_tile_data->host_status == CTRL_TILE_UNALLOC) {
		fprintf(stderr, "[Ctrl_FPGA] Internal Error: Tryinng to move tile from host to device but host memory was not allocated\n");
		fflush(stderr);
		exit(EXIT_FAILURE);
	}

	if (p_tile_data_impl->device_status == CTRL_TILE_UNALLOC) {
		fprintf(stderr, "[Ctrl_FPGA] Internal Error: Tryinng to move tile from host to device but device memory was not allocated\n");
		fflush(stderr);
		exit(EXIT_FAILURE);
	}

	if (p_tile_data->host_status == CTRL_TILE_INVALID) {
		fprintf(stderr, "[Ctrl_FPGA] Warning: Moving a tile from host to device with invalid data on host memory\n");
		fflush(stderr);
	}

	// If tile is not updated perform the transfer
	if (!(p_tile_data->host_status == CTRL_TILE_VALID && p_tile_data_impl->device_status == CTRL_TILE_VALID) || p_ctrl->dependance_mode == CTRL_MODE_EXPLICIT) {
		Ctrl_FPGA_EvalTaskMoveToInner(p_ctrl, p_tile);
	}
}

void Ctrl_FPGA_EvalTaskMoveFrom(Ctrl_FPGA *p_ctrl, Ctrl_Task *p_task) {
	HitTile        *p_tile           = p_task->p_tile;
	Ctrl_Tile      *p_tile_data      = (Ctrl_Tile *)(p_tile->ext);
	Ctrl_Tile_Impl *p_tile_data_impl = &p_tile_data->p_impls[p_ctrl->global_id];

	if (hit_tileIsNull(*p_tile)) return;

	if (p_tile_data->host_status == CTRL_TILE_UNALLOC) {
		fprintf(stderr, "[Ctrl_FPGA] Internal Error: Trying to move tile from device to host but host memory was not allocated\n");
		fflush(stderr);
		exit(EXIT_FAILURE);
	}

	if (p_tile_data_impl->device_status == CTRL_TILE_UNALLOC) {
		fprintf(stderr, "[Ctrl_FPGA] Internal Error: Trying to move tile from device to host but device memory was not allocated\n");
		fflush(stderr);
		exit(EXIT_FAILURE);
	}

	if (p_tile_data_impl->device_status == CTRL_TILE_INVALID) {
		fprintf(stderr, "[Ctrl_FPGA] Warning: Moving a tile from device to host with invalid data on device memory\n");
		fflush(stderr);
	}

	// If tile is not updated perform the transfer
	if (!(p_tile_data->host_status == CTRL_TILE_VALID && p_tile_data_impl->device_status == CTRL_TILE_VALID) || p_ctrl->dependance_mode == CTRL_MODE_EXPLICIT) {
		Ctrl_FPGA_EvalTaskMoveFromInner(p_ctrl, p_tile);
	}
}

void Ctrl_FPGA_EvalTaskWaitTile(Ctrl_FPGA *p_ctrl, Ctrl_Task *p_task) {
	HitTile *p_tile = p_task->p_tile;

	if (hit_tileIsNull(*p_tile)) return;

	Ctrl_FPGA_WaitTileInner(p_ctrl, (Ctrl_Tile *)(p_tile->ext));
}

void Ctrl_FPGA_EvalTaskSetDependanceMode(Ctrl_FPGA *p_ctrl, Ctrl_Task *p_task) {
	p_ctrl->dependance_mode = p_task->flags;
}

///@endcond

//

// Created by carlo on 2026-01-17.
//

#ifndef CODECUDA_CUH
#define CODECUDA_CUH

#include <functional>

#include "CodeSimulationParams.hpp"

namespace CodeCuda
{

    enum class C_Res
    {
        OK,
        ERR
    };

    struct kernel_launcher
    {
        void SetKernelFunct(std::function<void(class CodeCudaContext*)> func)
        {
            kernel = std::move(func);
            valid = true;
        }
        void Execute(CodeCudaContext* ctx)
        {
            if (!valid)
            {
                return;
            }
            kernel(ctx);
            
        }
        std::function<void(class CodeCudaContext*)>* GetKernelFunct()
        {
            if (!valid)
            {
                return nullptr;
            }
            return &kernel;
        }
        bool valid = false;
    private:
        std::function<void(class CodeCudaContext*)> kernel{};
    };

    struct cpu_launcher
    {
        void SetCPUFunct(std::function<void()> func)
        {
            task = std::move(func);
            valid = true;
        }
        
        void Execute()
        {
            if (!valid)
            {
                return;
            }
            task();
        }
        
        std::function<void()>* GetCPUFunct()
        {
            if (!valid)
            {
                return nullptr;
            }
            return &task;
        }
    private:
        bool valid = false;
        std::function<void()> task{};
    };

    class CodeCudaContext
    {
    public:
        C_Res C_Init();
        C_Res C_Shutdown();
        
        C_Res C_InitFromExternalDevice(uint8_t *vkDeviceUUID, size_t UUID_SIZE);
        C_Res C_ImportExternalBuffer(HANDLE win_handle, size_t buffer_size, uint32_t element_count);
        C_Res C_ImportExternalSemaphore(HANDLE win_handle);

        C_Res C_SignalExternalSemaphore(uint64_t signal_value);
        C_Res C_WaitExternalSemaphore(uint64_t wait_value);
        
        C_Res C_SetPreKernelFunction(std::function<void()> funct);
        C_Res C_SetKernelLauncherFunction(std::function<void(CodeCudaContext*)> kernel_funct);
        
        C_Res C_ExecuteCPU();
        C_Res C_ExecuteKernel();
        
        cudaStream_t stream = nullptr;
        int device = -1;
        bool initialized = false;
        int mapped_buffer_element_count = -1;
        void *mappedPtr = nullptr;
        
        float curr_t = 0.0f;
        float time_step = 1.0f / 30.0f;

    private:
        int id = -1;
        kernel_launcher kernel_launcher;
        cpu_launcher cpu_launcher;
        cudaExternalSemaphore_t external_semaphore = {};
    };
    
    C_Res C_Matmul(CodeCudaContext *code_cuda_context, int M, int N, int K, const float *a, const float *b, float *c);
    
    // simulation
    namespace FluidSimulation
    {
        inline int s_width = 256 + 128;
        inline int s_height = 256 + 128;
        //used to map simulation to external buffers
        kernel_launcher& C_GetKernelLauncherMappers(int type);
        C_Res C_UpdateSimGPU(CodeCudaContext *code_cuda_context);
        C_Res C_UpdateSimCPU();
        C_Res C_AddRandomVelocity(int scale);
        C_Res C_MapImageToSmoke(int w_source, int h_source, int element_offset, void* data);
        C_Res C_MapSolidMask(int w_source, int h_source, int* data);
        C_Res C_MapVectorFieldUV(int w_source, int h_source, int element_offset, void* data);
        C_Res C_AddVelocity(int x_pos, int y_pos, int radius, float vel_x, float vel_y);
        C_Res C_AddSmoke(int x_pos, int y_pos, int radius, float value_x, float value_y, float value_z, float density);
        C_Res C_AddPressure(int x_pos, int y_pos, int radius, float value);
        C_Res C_SetSolid(int x_pos, int y_pos, int radius, bool solid);
        C_Res C_AddRadialVelocity(int x_pos, int y_pos, int radius, float scale);
        C_Res C_AddVelocityGPU(int x_pos, int y_pos, int radius, float vel_x, float vel_y,
                               CodeCudaContext *code_cuda_context);
        C_Res C_AddSmokeGPU(int x_pos, int y_pos, int radius, float val_x, float val_y, float val_z, float density,
                            CodeCudaContext *code_cuda_context);
        C_Res C_AddPressureGPU(int x_pos, int y_pos, int radius, float value,
                               CodeCudaContext *code_cuda_context);
        C_Res C_SetSimulationParams(const sim_params *params);
        C_Res C_GetSimulationParams(sim_params *params);
        C_Res C_SetDebugSimulation(bool value);
        C_Res C_RestartSimulation();
        C_Res C_SetSimulationResolution(int w, int h);
    }

    C_Res C_InitEngine();
    C_Res C_ShutDownEngine();
    inline int contexts_id_count = 0;

    namespace CodeBenchmarking
    {
        void C_Matmul_Test(CodeCudaContext *code_cuda_context, int M, int N, int K, const float *a, const float *b,
                           float *c, int runs);
    }

} // namespace CodeCuda

#endif // CODECUDA_CUH

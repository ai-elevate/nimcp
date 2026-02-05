#include <stddef.h>  /* for NULL */
//=============================================================================
// nimcp_model_loader.c - Pre-trained Model Loading Implementation
//=============================================================================
/**
 * @file nimcp_model_loader.c
 * @brief Full implementation of model loading, validation, and versioning
 *
 * WHAT: Comprehensive model file I/O with validation and version support
 * WHY:  Enable deployment of pre-trained NIMCP models
 * HOW:  Binary file format with header, metadata, architecture, and weights
 *
 * IMPLEMENTATION PHASES:
 * 1. File I/O and header parsing
 * 2. Version validation and compatibility
 * 3. Checksum verification (CRC32 and SHA256)
 * 4. Architecture deserialization
 * 5. Weight loading with format conversion
 * 6. Integration with brain_t API
 *
 * @author NIMCP Development Team
 * @date 2025-12-30
 * @version 1.0.0
 */

#include "io/model/nimcp_model_loader.h"
#include "io/serialization/nimcp_serialization.h"
#include "utils/memory/nimcp_memory.h"
#include "utils/logging/nimcp_logging.h"
#include "core/brain/nimcp_brain.h"
#include "plasticity/adaptive/nimcp_adaptive.h"
#include "api/nimcp_api_exception.h"
#include "utils/exception/nimcp_exception.h"
#include "utils/exception/nimcp_exception_macros.h"
#include "security/nimcp_path_traversal.h"

#include <stdio.h>
#include <stdlib.h>
#include <string.h>
#include <math.h>
#include <errno.h>
#include <sys/stat.h>

#ifdef _WIN32
#include <io.h>
#define F_OK 0
#define access _access
#else
#include <unistd.h>
#endif

#define LOG_MODULE "MODEL_LOADER"

/*=============================================================================
 * Health Agent Forward Declarations (Phase 8: Heartbeat for Long Operations)
 *===========================================================================*/
#include "utils/fault_tolerance/nimcp_health_agent_macros.h"

NIMCP_DECLARE_HEALTH_AGENT_ATOMIC(model_loader)

//=============================================================================
// Thread-Local Error State
//=============================================================================

#ifdef _WIN32
__declspec(thread) static char g_last_error[512] = {0};
#else
static __thread char g_last_error[512] = {0};
#endif

static void set_error(const char* format, ...)
{
    va_list args;
    va_start(args, format);
    vsnprintf(g_last_error, sizeof(g_last_error), format, args);
    va_end(args);
}

//=============================================================================
// Internal Structures
//=============================================================================

/**
 * @brief Internal loaded model structure
 */
struct nimcp_loaded_model {
    // Header information
    nimcp_model_header_t header;

    // Architecture
    nimcp_model_architecture_t architecture;

    // Metadata (may be NULL if not present)
    nimcp_model_metadata_t* metadata;

    // Weight data
    float* weights;
    size_t num_weights;
    nimcp_weight_format_t weight_format;

    // Source file info
    char* filepath;
    size_t file_size;

    // Validation state
    bool validated;
    nimcp_model_validation_t validation_result;
};

//=============================================================================
// CRC32 Implementation
//=============================================================================

/**
 * @brief CRC32 lookup table (generated from polynomial 0xEDB88320)
 */
static const uint32_t crc32_table[256] = {
    0x00000000, 0x77073096, 0xEE0E612C, 0x990951BA, 0x076DC419, 0x706AF48F,
    0xE963A535, 0x9E6495A3, 0x0EDB8832, 0x79DCB8A4, 0xE0D5E91E, 0x97D2D988,
    0x09B64C2B, 0x7EB17CBD, 0xE7B82D07, 0x90BF1D91, 0x1DB71064, 0x6AB020F2,
    0xF3B97148, 0x84BE41DE, 0x1ADAD47D, 0x6DDDE4EB, 0xF4D4B551, 0x83D385C7,
    0x136C9856, 0x646BA8C0, 0xFD62F97A, 0x8A65C9EC, 0x14015C4F, 0x63066CD9,
    0xFA0F3D63, 0x8D080DF5, 0x3B6E20C8, 0x4C69105E, 0xD56041E4, 0xA2677172,
    0x3C03E4D1, 0x4B04D447, 0xD20D85FD, 0xA50AB56B, 0x35B5A8FA, 0x42B2986C,
    0xDBBBC9D6, 0xACBCF940, 0x32D86CE3, 0x45DF5C75, 0xDCD60DCF, 0xABD13D59,
    0x26D930AC, 0x51DE003A, 0xC8D75180, 0xBFD06116, 0x21B4F4B5, 0x56B3C423,
    0xCFBA9599, 0xB8BDA50F, 0x2802B89E, 0x5F058808, 0xC60CD9B2, 0xB10BE924,
    0x2F6F7C87, 0x58684C11, 0xC1611DAB, 0xB6662D3D, 0x76DC4190, 0x01DB7106,
    0x98D220BC, 0xEFD5102A, 0x71B18589, 0x06B6B51F, 0x9FBFE4A5, 0xE8B8D433,
    0x7807C9A2, 0x0F00F934, 0x9609A88E, 0xE10E9818, 0x7F6A0DBB, 0x086D3D2D,
    0x91646C97, 0xE6635C01, 0x6B6B51F4, 0x1C6C6162, 0x856530D8, 0xF262004E,
    0x6C0695ED, 0x1B01A57B, 0x8208F4C1, 0xF50FC457, 0x65B0D9C6, 0x12B7E950,
    0x8BBEB8EA, 0xFCB9887C, 0x62DD1DDF, 0x15DA2D49, 0x8CD37CF3, 0xFBD44C65,
    0x4DB26158, 0x3AB551CE, 0xA3BC0074, 0xD4BB30E2, 0x4ADFA541, 0x3DD895D7,
    0xA4D1C46D, 0xD3D6F4FB, 0x4369E96A, 0x346ED9FC, 0xAD678846, 0xDA60B8D0,
    0x44042D73, 0x33031DE5, 0xAA0A4C5F, 0xDD0D7CC9, 0x5005713C, 0x270241AA,
    0xBE0B1010, 0xC90C2086, 0x5768B525, 0x206F85B3, 0xB966D409, 0xCE61E49F,
    0x5EDEF90E, 0x29D9C998, 0xB0D09822, 0xC7D7A8B4, 0x59B33D17, 0x2EB40D81,
    0xB7BD5C3B, 0xC0BA6CAD, 0xEDB88320, 0x9ABFB3B6, 0x03B6E20C, 0x74B1D29A,
    0xEAD54739, 0x9DD277AF, 0x04DB2615, 0x73DC1683, 0xE3630B12, 0x94643B84,
    0x0D6D6A3E, 0x7A6A5AA8, 0xE40ECF0B, 0x9309FF9D, 0x0A00AE27, 0x7D079EB1,
    0xF00F9344, 0x8708A3D2, 0x1E01F268, 0x6906C2FE, 0xF762575D, 0x806567CB,
    0x196C3671, 0x6E6B06E7, 0xFED41B76, 0x89D32BE0, 0x10DA7A5A, 0x67DD4ACC,
    0xF9B9DF6F, 0x8EBEEFF9, 0x17B7BE43, 0x60B08ED5, 0xD6D6A3E8, 0xA1D1937E,
    0x38D8C2C4, 0x4FDFF252, 0xD1BB67F1, 0xA6BC5767, 0x3FB506DD, 0x48B2364B,
    0xD80D2BDA, 0xAF0A1B4C, 0x36034AF6, 0x41047A60, 0xDF60EFC3, 0xA867DF55,
    0x316E8EEF, 0x4669BE79, 0xCB61B38C, 0xBC66831A, 0x256FD2A0, 0x5268E236,
    0xCC0C7795, 0xBB0B4703, 0x220216B9, 0x5505262F, 0xC5BA3BBE, 0xB2BD0B28,
    0x2BB45A92, 0x5CB36A04, 0xC2D7FFA7, 0xB5D0CF31, 0x2CD99E8B, 0x5BDEAE1D,
    0x9B64C2B0, 0xEC63F226, 0x756AA39C, 0x026D930A, 0x9C0906A9, 0xEB0E363F,
    0x72076785, 0x05005713, 0x95BF4A82, 0xE2B87A14, 0x7BB12BAE, 0x0CB61B38,
    0x92D28E9B, 0xE5D5BE0D, 0x7CDCEFB7, 0x0BDBDF21, 0x86D3D2D4, 0xF1D4E242,
    0x68DDB3F8, 0x1FDA836E, 0x81BE16CD, 0xF6B9265B, 0x6FB077E1, 0x18B74777,
    0x88085AE6, 0xFF0F6A70, 0x66063BCA, 0x11010B5C, 0x8F659EFF, 0xF862AE69,
    0x616BFFD3, 0x166CCF45, 0xA00AE278, 0xD70DD2EE, 0x4E048354, 0x3903B3C2,
    0xA7672661, 0xD06016F7, 0x4969474D, 0x3E6E77DB, 0xAED16A4A, 0xD9D65ADC,
    0x40DF0B66, 0x37D83BF0, 0xA9BCAE53, 0xDEBB9EC5, 0x47B2CF7F, 0x30B5FFE9,
    0xBDBDF21C, 0xCABAC28A, 0x53B39330, 0x24B4A3A6, 0xBAD03605, 0xCDD706B3,
    0x54DE5729, 0x23D967BF, 0xB3667A2E, 0xC4614AB8, 0x5D681B02, 0x2A6F2B94,
    0xB40BBE37, 0xC30C8EA1, 0x5A05DF1B, 0x2D02EF8D
};

/**
 * @brief Compute CRC32 checksum
 */
static uint32_t compute_crc32(const uint8_t* data, size_t length)
{
    uint32_t crc = 0xFFFFFFFF;
    for (size_t i = 0; i < length; i++) {
        crc = crc32_table[(crc ^ data[i]) & 0xFF] ^ (crc >> 8);
    }
    return crc ^ 0xFFFFFFFF;
}

//=============================================================================
// Endianness Handling
//=============================================================================

/**
 * @brief Check if system is little-endian
 */
static bool is_little_endian(void)
{
    uint32_t test = 1;
    return *((uint8_t*)&test) == 1;
}

/**
 * @brief Swap bytes for 16-bit value
 */
static uint16_t swap16(uint16_t val)
{
    return (val << 8) | (val >> 8);
}

/**
 * @brief Swap bytes for 32-bit value
 */
static uint32_t swap32(uint32_t val)
{
    return ((val & 0xFF000000) >> 24) |
           ((val & 0x00FF0000) >> 8) |
           ((val & 0x0000FF00) << 8) |
           ((val & 0x000000FF) << 24);
}

/**
 * @brief Read 16-bit little-endian value from buffer
 */
static uint16_t read_le16(const uint8_t* buf)
{
    return (uint16_t)buf[0] | ((uint16_t)buf[1] << 8);
}

/**
 * @brief Read 32-bit little-endian value from buffer
 */
static uint32_t read_le32(const uint8_t* buf)
{
    return (uint32_t)buf[0] |
           ((uint32_t)buf[1] << 8) |
           ((uint32_t)buf[2] << 16) |
           ((uint32_t)buf[3] << 24);
}

/**
 * @brief Write 16-bit little-endian value to buffer
 */
static void write_le16(uint8_t* buf, uint16_t val)
{
    buf[0] = (uint8_t)(val & 0xFF);
    buf[1] = (uint8_t)((val >> 8) & 0xFF);
}

/**
 * @brief Write 32-bit little-endian value to buffer
 */
static void write_le32(uint8_t* buf, uint32_t val)
{
    buf[0] = (uint8_t)(val & 0xFF);
    buf[1] = (uint8_t)((val >> 8) & 0xFF);
    buf[2] = (uint8_t)((val >> 16) & 0xFF);
    buf[3] = (uint8_t)((val >> 24) & 0xFF);
}

/**
 * @brief Read float from little-endian buffer
 */
static float read_le_float(const uint8_t* buf)
{
    uint32_t val = read_le32(buf);
    float f;
    memcpy(&f, &val, sizeof(float));
    return f;
}

/**
 * @brief Write float to little-endian buffer
 */
static void write_le_float(uint8_t* buf, float f)
{
    uint32_t val;
    memcpy(&val, &f, sizeof(float));
    write_le32(buf, val);
}

//=============================================================================
// Default Options
//=============================================================================

nimcp_model_load_options_t nimcp_model_load_options_default(void)
{
    nimcp_model_load_options_t options = {
        .validate_checksum = true,
        .validate_weights = true,
        .allow_newer_version = false,
        .verbose = false,
        .lazy_load = false,
        .memory_map = false,
        .read_buffer_size = 65536,  // 64KB
        .password = NULL,
        .password_len = 0,
        .ignore_arch_mismatch = false
    };
    return options;
}

nimcp_model_save_options_t nimcp_model_save_options_default(void)
{
    nimcp_model_save_options_t options = {
        .compress = true,
        .compression_level = 6,
        .include_checksum = true,
        .include_sha256 = false,
        .include_metadata = true,
        .password = NULL,
        .password_len = 0,
        .weight_format = NIMCP_WEIGHT_FORMAT_FLOAT32,
        .prune_weights = false,
        .prune_threshold = 0.0f,
        .mark_fine_tunable = true,
        .sensory_layer_end = 0,
        .cognitive_layer_end = 0
    };
    return options;
}

//=============================================================================
// Header Parsing
//=============================================================================

/**
 * @brief Parse model header from buffer
 */
static nimcp_model_result_t parse_header(const uint8_t* buf, size_t buf_size,
                                         nimcp_model_header_t* header)
{
    // Minimum header size check
    if (buf_size < 64) {
        set_error("Buffer too small for header: %zu bytes", buf_size);
        return NIMCP_MODEL_ERROR_INCOMPLETE;
    }

    // Parse magic
    memcpy(header->magic, buf, 4);

    // Validate magic
    if (header->magic[0] != NIMCP_MODEL_MAGIC_0 ||
        header->magic[1] != NIMCP_MODEL_MAGIC_1 ||
        header->magic[2] != NIMCP_MODEL_MAGIC_2 ||
        header->magic[3] != NIMCP_MODEL_MAGIC_3) {
        set_error("Invalid magic bytes: expected 'NIMP', got '%c%c%c%c'",
                 header->magic[0], header->magic[1],
                 header->magic[2], header->magic[3]);
        return NIMCP_MODEL_ERROR_INVALID_MAGIC;
    }

    // Parse version (little-endian)
    header->version_major = read_le16(buf + 4);
    header->version_minor = read_le16(buf + 6);
    header->version_patch = read_le16(buf + 8);

    // Parse flags and offsets
    header->flags = read_le32(buf + 10);
    header->header_size = read_le32(buf + 14);
    header->data_offset = read_le32(buf + 18);
    header->data_size = read_le32(buf + 22);
    header->original_size = read_le32(buf + 26);
    header->checksum_crc = read_le32(buf + 30);

    // Parse SHA256 checksum if present
    if (header->flags & NIMCP_MODEL_FLAG_CHECKSUM_SHA) {
        memcpy(header->checksum_sha, buf + 34, 32);
    } else {
        memset(header->checksum_sha, 0, 32);
    }

    return NIMCP_MODEL_SUCCESS;
}

/**
 * @brief Write model header to buffer
 */
static size_t write_header(uint8_t* buf, const nimcp_model_header_t* header)
{
    // Magic
    buf[0] = NIMCP_MODEL_MAGIC_0;
    buf[1] = NIMCP_MODEL_MAGIC_1;
    buf[2] = NIMCP_MODEL_MAGIC_2;
    buf[3] = NIMCP_MODEL_MAGIC_3;

    // Version
    write_le16(buf + 4, header->version_major);
    write_le16(buf + 6, header->version_minor);
    write_le16(buf + 8, header->version_patch);

    // Flags and offsets
    write_le32(buf + 10, header->flags);
    write_le32(buf + 14, header->header_size);
    write_le32(buf + 18, header->data_offset);
    write_le32(buf + 22, header->data_size);
    write_le32(buf + 26, header->original_size);
    write_le32(buf + 30, header->checksum_crc);

    // SHA256 checksum
    memcpy(buf + 34, header->checksum_sha, 32);

    return 66;  // Header size
}

//=============================================================================
// Architecture Parsing
//=============================================================================

/**
 * @brief Parse architecture from buffer
 */
static nimcp_model_result_t parse_architecture(const uint8_t* buf, size_t buf_size,
                                               size_t* offset,
                                               nimcp_model_architecture_t* arch)
{
    size_t pos = *offset;

    // Need at least basic architecture fields
    if (buf_size - pos < 36) {
        set_error("Buffer too small for architecture at offset %zu", pos);
        return NIMCP_MODEL_ERROR_INCOMPLETE;
    }

    // Parse basic fields
    arch->num_neurons = read_le32(buf + pos);
    pos += 4;

    arch->num_synapses = read_le32(buf + pos);
    pos += 4;

    arch->num_layers = read_le32(buf + pos);
    pos += 4;

    arch->input_size = read_le32(buf + pos);
    pos += 4;

    arch->output_size = read_le32(buf + pos);
    pos += 4;

    // Validate limits
    if (arch->num_neurons > NIMCP_MODEL_MAX_NEURONS) {
        set_error("Neuron count %u exceeds maximum %u",
                 arch->num_neurons, NIMCP_MODEL_MAX_NEURONS);
        return NIMCP_MODEL_ERROR_NEURON_COUNT;
    }

    if (arch->num_synapses > NIMCP_MODEL_MAX_SYNAPSES) {
        set_error("Synapse count %u exceeds maximum %u",
                 arch->num_synapses, NIMCP_MODEL_MAX_SYNAPSES);
        return NIMCP_MODEL_ERROR_SYNAPSE_COUNT;
    }

    if (arch->num_layers > NIMCP_MODEL_MAX_LAYERS) {
        set_error("Layer count %u exceeds maximum %u",
                 arch->num_layers, NIMCP_MODEL_MAX_LAYERS);
        return NIMCP_MODEL_ERROR_INVALID_ARCHITECTURE;
    }

    // Parse layer configuration if layers > 0
    arch->layer_sizes = NULL;
    arch->layer_types = NULL;

    if (arch->num_layers > 0) {
        // Check buffer space for layer arrays
        size_t layer_data_size = arch->num_layers * (sizeof(uint32_t) + sizeof(uint8_t));
        if (buf_size - pos < layer_data_size) {
            set_error("Buffer too small for layer configuration");
            return NIMCP_MODEL_ERROR_INCOMPLETE;
        }

        // Allocate layer arrays
        arch->layer_sizes = nimcp_malloc(arch->num_layers * sizeof(uint32_t));
        arch->layer_types = nimcp_malloc(arch->num_layers * sizeof(uint8_t));

        if (!arch->layer_sizes || !arch->layer_types) {
            nimcp_free(arch->layer_sizes);
            nimcp_free(arch->layer_types);
            set_error("Failed to allocate layer configuration");
            return NIMCP_MODEL_ERROR_MEMORY;
        }

        // Read layer sizes
        for (uint32_t i = 0; i < arch->num_layers; i++) {
            arch->layer_sizes[i] = read_le32(buf + pos);
            pos += 4;
        }

        // Read layer types
        for (uint32_t i = 0; i < arch->num_layers; i++) {
            arch->layer_types[i] = buf[pos++];
        }
    }

    // Parse network topology hints
    arch->sparsity = read_le_float(buf + pos);
    pos += 4;

    arch->ei_ratio = read_le_float(buf + pos);
    pos += 4;

    arch->connectivity_type = buf[pos++];

    // Parse fine-tuning hints
    arch->sensory_layer_end = read_le32(buf + pos);
    pos += 4;

    arch->cognitive_layer_end = read_le32(buf + pos);
    pos += 4;

    arch->fine_tunable = buf[pos++] != 0;

    *offset = pos;
    return NIMCP_MODEL_SUCCESS;
}

/**
 * @brief Write architecture to buffer
 */
static size_t write_architecture(uint8_t* buf, const nimcp_model_architecture_t* arch)
{
    size_t pos = 0;

    // Basic fields
    write_le32(buf + pos, arch->num_neurons);
    pos += 4;

    write_le32(buf + pos, arch->num_synapses);
    pos += 4;

    write_le32(buf + pos, arch->num_layers);
    pos += 4;

    write_le32(buf + pos, arch->input_size);
    pos += 4;

    write_le32(buf + pos, arch->output_size);
    pos += 4;

    // Layer configuration
    if (arch->num_layers > 0 && arch->layer_sizes && arch->layer_types) {
        for (uint32_t i = 0; i < arch->num_layers; i++) {
            write_le32(buf + pos, arch->layer_sizes[i]);
            pos += 4;
        }
        for (uint32_t i = 0; i < arch->num_layers; i++) {
            buf[pos++] = arch->layer_types[i];
        }
    }

    // Network topology hints
    write_le_float(buf + pos, arch->sparsity);
    pos += 4;

    write_le_float(buf + pos, arch->ei_ratio);
    pos += 4;

    buf[pos++] = arch->connectivity_type;

    // Fine-tuning hints
    write_le32(buf + pos, arch->sensory_layer_end);
    pos += 4;

    write_le32(buf + pos, arch->cognitive_layer_end);
    pos += 4;

    buf[pos++] = arch->fine_tunable ? 1 : 0;

    return pos;
}

//=============================================================================
// Metadata Parsing
//=============================================================================

/**
 * @brief Parse metadata from buffer
 */
static nimcp_model_result_t parse_metadata(const uint8_t* buf, size_t buf_size,
                                           size_t* offset,
                                           nimcp_model_metadata_t* meta)
{
    size_t pos = *offset;

    // Check minimum size
    if (buf_size - pos < sizeof(nimcp_model_metadata_t)) {
        set_error("Buffer too small for metadata");
        return NIMCP_MODEL_ERROR_INCOMPLETE;
    }

    // Copy fixed-size strings
    memcpy(meta->model_name, buf + pos, 64);
    meta->model_name[63] = '\0';  // Ensure null termination
    pos += 64;

    memcpy(meta->model_version, buf + pos, 16);
    meta->model_version[15] = '\0';
    pos += 16;

    memcpy(meta->training_date, buf + pos, 32);
    meta->training_date[31] = '\0';
    pos += 32;

    memcpy(meta->framework_version, buf + pos, 16);
    meta->framework_version[15] = '\0';
    pos += 16;

    // Training configuration
    meta->training_epochs = read_le32(buf + pos);
    pos += 4;

    meta->training_samples = read_le32(buf + pos);
    pos += 4;

    meta->final_loss = read_le_float(buf + pos);
    pos += 4;

    meta->final_accuracy = read_le_float(buf + pos);
    pos += 4;

    meta->learning_rate = read_le_float(buf + pos);
    pos += 4;

    // Performance metrics
    meta->inference_time_ms = read_le_float(buf + pos);
    pos += 4;

    meta->memory_usage_mb = read_le_float(buf + pos);
    pos += 4;

    // Task information
    meta->task_type = buf[pos++];

    memcpy(meta->task_description, buf + pos, 128);
    meta->task_description[127] = '\0';
    pos += 128;

    *offset = pos;
    return NIMCP_MODEL_SUCCESS;
}

/**
 * @brief Write metadata to buffer
 */
static size_t write_metadata(uint8_t* buf, const nimcp_model_metadata_t* meta)
{
    size_t pos = 0;

    // Fixed-size strings
    memcpy(buf + pos, meta->model_name, 64);
    pos += 64;

    memcpy(buf + pos, meta->model_version, 16);
    pos += 16;

    memcpy(buf + pos, meta->training_date, 32);
    pos += 32;

    memcpy(buf + pos, meta->framework_version, 16);
    pos += 16;

    // Training configuration
    write_le32(buf + pos, meta->training_epochs);
    pos += 4;

    write_le32(buf + pos, meta->training_samples);
    pos += 4;

    write_le_float(buf + pos, meta->final_loss);
    pos += 4;

    write_le_float(buf + pos, meta->final_accuracy);
    pos += 4;

    write_le_float(buf + pos, meta->learning_rate);
    pos += 4;

    // Performance metrics
    write_le_float(buf + pos, meta->inference_time_ms);
    pos += 4;

    write_le_float(buf + pos, meta->memory_usage_mb);
    pos += 4;

    // Task information
    buf[pos++] = meta->task_type;

    memcpy(buf + pos, meta->task_description, 128);
    pos += 128;

    return pos;
}

//=============================================================================
// Weight Validation
//=============================================================================

/**
 * @brief Validate weight values for NaN/Inf
 */
static nimcp_model_result_t validate_weights(const float* weights, size_t count,
                                             nimcp_model_validation_t* validation)
{
    validation->nan_count = 0;
    validation->inf_count = 0;
    validation->weight_min = INFINITY;
    validation->weight_max = -INFINITY;

    double sum = 0.0;
    double sum_sq = 0.0;

    for (size_t i = 0; i < count; i++) {
        float w = weights[i];

        if (isnan(w)) {
            validation->nan_count++;
        } else if (isinf(w)) {
            validation->inf_count++;
        } else {
            if (w < validation->weight_min) validation->weight_min = w;
            if (w > validation->weight_max) validation->weight_max = w;
            sum += w;
            sum_sq += (double)w * w;
        }
    }

    size_t valid_count = count - validation->nan_count - validation->inf_count;
    if (valid_count > 0) {
        validation->weight_mean = (float)(sum / valid_count);
        double variance = (sum_sq / valid_count) -
                          (validation->weight_mean * validation->weight_mean);
        validation->weight_std = (float)sqrt(variance > 0 ? variance : 0);
    } else {
        validation->weight_mean = 0.0f;
        validation->weight_std = 0.0f;
    }

    // Check for errors
    if (validation->nan_count > 0) {
        set_error("Found %u NaN values in weights", validation->nan_count);
        return NIMCP_MODEL_ERROR_NAN_DETECTED;
    }

    if (validation->inf_count > 0) {
        set_error("Found %u Inf values in weights", validation->inf_count);
        return NIMCP_MODEL_ERROR_INF_DETECTED;
    }

    return NIMCP_MODEL_SUCCESS;
}

//=============================================================================
// Version Compatibility
//=============================================================================

bool nimcp_model_version_compatible(uint16_t major, uint16_t minor)
{
    // Major version must match exactly for compatibility
    if (major > NIMCP_MODEL_VERSION_MAJOR) {
        return false;
    }

    // If major version is older but within minimum, it's compatible
    if (major < NIMCP_MODEL_MIN_MAJOR) {
        return false;
    }

    // If same major version, any minor version is compatible
    if (major == NIMCP_MODEL_VERSION_MAJOR) {
        return true;
    }

    // Older major version: check if above minimum
    return (major >= NIMCP_MODEL_MIN_MAJOR);
}

//=============================================================================
// Core API Implementation
//=============================================================================

nimcp_model_result_t nimcp_model_validate_file(const char* filepath,
                                               nimcp_model_validation_t* validation)
{
    // Initialize validation result
    memset(validation, 0, sizeof(nimcp_model_validation_t));

    if (!filepath) {
        set_error("NULL filepath");
        validation->result = NIMCP_MODEL_ERROR_INVALID_PARAM;
        snprintf(validation->error_message, sizeof(validation->error_message),
                "NULL filepath");
        return NIMCP_MODEL_ERROR_INVALID_PARAM;
    }

    // P1-3 fix: Path traversal validation
    if (!nimcp_path_is_safe(filepath)) {
        set_error("Path validation failed: %s", filepath);
        validation->result = NIMCP_MODEL_ERROR_INVALID_PARAM;
        snprintf(validation->error_message, sizeof(validation->error_message),
                "Path validation failed: %s", filepath);
        LOG_ERROR(LOG_MODULE, "Path traversal attack detected: %s", filepath);
        return NIMCP_MODEL_ERROR_INVALID_PARAM;
    }

    // Check file exists
    if (access(filepath, F_OK) != 0) {
        set_error("File not found: %s", filepath);
        validation->result = NIMCP_MODEL_ERROR_FILE_NOT_FOUND;
        snprintf(validation->error_message, sizeof(validation->error_message),
                "File not found: %s", filepath);
        return NIMCP_MODEL_ERROR_FILE_NOT_FOUND;
    }

    // Open file
    FILE* file = fopen(filepath, "rb");
    if (!file) {
        NIMCP_THROW_IO(NIMCP_ERROR_IO, filepath,
                      "Cannot open model file: %s (errno=%d)", filepath, errno);
        set_error("Cannot open file: %s (errno=%d)", filepath, errno);
        validation->result = NIMCP_MODEL_ERROR_FILE_READ;
        snprintf(validation->error_message, sizeof(validation->error_message),
                "Cannot open file: %s", filepath);
        return NIMCP_MODEL_ERROR_FILE_READ;
    }

    // Get file size
    fseek(file, 0, SEEK_END);
    long file_size = ftell(file);
    fseek(file, 0, SEEK_SET);

    if (file_size > (long)NIMCP_MODEL_MAX_FILE_SIZE) {
        fclose(file);
        set_error("File too large: %ld bytes", file_size);
        validation->result = NIMCP_MODEL_ERROR_FILE_SIZE;
        return NIMCP_MODEL_ERROR_FILE_SIZE;
    }

    // Read header
    uint8_t header_buf[66];
    if (fread(header_buf, 1, 66, file) != 66) {
        fclose(file);
        set_error("Failed to read header");
        validation->result = NIMCP_MODEL_ERROR_FILE_READ;
        return NIMCP_MODEL_ERROR_FILE_READ;
    }

    // Parse header
    nimcp_model_header_t header;
    nimcp_model_result_t result = parse_header(header_buf, 66, &header);
    if (result != NIMCP_MODEL_SUCCESS) {
        fclose(file);
        validation->result = result;
        snprintf(validation->error_message, sizeof(validation->error_message),
                "%s", g_last_error);
        return result;
    }

    validation->header_valid = true;
    validation->file_version_major = header.version_major;
    validation->file_version_minor = header.version_minor;
    validation->file_version_patch = header.version_patch;

    // Check version compatibility
    validation->version_compatible = nimcp_model_version_compatible(
        header.version_major, header.version_minor);

    if (!validation->version_compatible) {
        fclose(file);
        set_error("Incompatible version: v%u.%u.%u (loader supports v%u.%u+)",
                 header.version_major, header.version_minor, header.version_patch,
                 NIMCP_MODEL_MIN_MAJOR, NIMCP_MODEL_MIN_MINOR);
        validation->result = NIMCP_MODEL_ERROR_VERSION_UNSUPPORTED;
        snprintf(validation->error_message, sizeof(validation->error_message),
                "%s", g_last_error);
        return NIMCP_MODEL_ERROR_VERSION_UNSUPPORTED;
    }

    // Verify CRC32 checksum if present
    if (header.flags & NIMCP_MODEL_FLAG_CHECKSUM_CRC) {
        // Read data section for checksum
        if (fseek(file, header.data_offset, SEEK_SET) != 0) {
            fclose(file);
            set_error("Failed to seek to data section");
            validation->result = NIMCP_MODEL_ERROR_FILE_READ;
            return NIMCP_MODEL_ERROR_FILE_READ;
        }

        uint8_t* data = nimcp_malloc(header.data_size);
        if (!data) {
            NIMCP_THROW_MEMORY(NIMCP_ERROR_NO_MEMORY, header.data_size,
                              "Failed to allocate %u bytes for checksum validation", header.data_size);
            fclose(file);
            set_error("Failed to allocate %u bytes for checksum", header.data_size);
            validation->result = NIMCP_MODEL_ERROR_MEMORY;
            return NIMCP_MODEL_ERROR_MEMORY;
        }

        if (fread(data, 1, header.data_size, file) != header.data_size) {
            nimcp_free(data);
            fclose(file);
            set_error("Failed to read data section");
            validation->result = NIMCP_MODEL_ERROR_FILE_READ;
            return NIMCP_MODEL_ERROR_FILE_READ;
        }

        uint32_t computed_crc = compute_crc32(data, header.data_size);
        nimcp_free(data);

        if (computed_crc != header.checksum_crc) {
            fclose(file);
            set_error("CRC32 mismatch: expected 0x%08X, computed 0x%08X",
                     header.checksum_crc, computed_crc);
            validation->result = NIMCP_MODEL_ERROR_CHECKSUM_MISMATCH;
            snprintf(validation->error_message, sizeof(validation->error_message),
                    "%s", g_last_error);
            return NIMCP_MODEL_ERROR_CHECKSUM_MISMATCH;
        }

        validation->checksum_valid = true;
    } else {
        // No checksum to validate
        validation->checksum_valid = true;
    }

    fclose(file);

    validation->result = NIMCP_MODEL_SUCCESS;
    validation->architecture_valid = true;  // Will be fully validated on load
    validation->weights_valid = true;       // Will be fully validated on load

    return NIMCP_MODEL_SUCCESS;
}

nimcp_model_result_t nimcp_model_load(const char* filepath,
                                      const nimcp_model_load_options_t* options,
                                      nimcp_loaded_model_t** model_out)
{
    /* Phase 8: Send heartbeat at start of model loading */
    model_loader_heartbeat("model_load", 0.0f);

    // Use default options if not provided
    nimcp_model_load_options_t opts = options ? *options : nimcp_model_load_options_default();

    if (!filepath || !model_out) {
        set_error("NULL parameter");
        return NIMCP_MODEL_ERROR_INVALID_PARAM;
    }

    *model_out = NULL;

    /* Phase 8: Heartbeat after validation */
    model_loader_heartbeat("model_load_validate", 0.1f);

    // First validate the file
    nimcp_model_validation_t validation;
    nimcp_model_result_t result = nimcp_model_validate_file(filepath, &validation);

    if (result != NIMCP_MODEL_SUCCESS && !opts.allow_newer_version) {
        return result;
    }

    // P1-3 fix: Path traversal validation (redundant check for defense-in-depth)
    if (!nimcp_path_is_safe(filepath)) {
        set_error("Path validation failed: %s", filepath);
        LOG_ERROR(LOG_MODULE, "Path traversal attack detected: %s", filepath);
        return NIMCP_MODEL_ERROR_INVALID_PARAM;
    }

    // Open file
    FILE* file = fopen(filepath, "rb");
    if (!file) {
        set_error("Cannot open file: %s", filepath);
        return NIMCP_MODEL_ERROR_FILE_READ;
    }

    // Get file size
    fseek(file, 0, SEEK_END);
    long file_size = ftell(file);
    fseek(file, 0, SEEK_SET);

    // Allocate model structure
    nimcp_loaded_model_t* model = nimcp_calloc(1, sizeof(nimcp_loaded_model_t));
    if (!model) {
        NIMCP_THROW_MEMORY(NIMCP_ERROR_NO_MEMORY, sizeof(nimcp_loaded_model_t),
                          "Failed to allocate model structure");
        fclose(file);
        set_error("Failed to allocate model structure");
        return NIMCP_MODEL_ERROR_MEMORY;
    }

    // Store file info
    model->filepath = nimcp_strdup(filepath);
    model->file_size = (size_t)file_size;

    // Read header
    uint8_t header_buf[66];
    if (fread(header_buf, 1, 66, file) != 66) {
        nimcp_free(model->filepath);
        nimcp_free(model);
        fclose(file);
        set_error("Failed to read header");
        return NIMCP_MODEL_ERROR_FILE_READ;
    }

    result = parse_header(header_buf, 66, &model->header);
    if (result != NIMCP_MODEL_SUCCESS) {
        nimcp_free(model->filepath);
        nimcp_free(model);
        fclose(file);
        return result;
    }

    // Read architecture section
    // Architecture starts right after header
    size_t arch_offset = model->header.header_size;
    fseek(file, (long)arch_offset, SEEK_SET);

    // Read enough for architecture
    size_t arch_max_size = 1024 + NIMCP_MODEL_MAX_LAYERS * 5;  // Conservative estimate
    uint8_t* arch_buf = nimcp_malloc(arch_max_size);
    if (!arch_buf) {
        nimcp_free(model->filepath);
        nimcp_free(model);
        fclose(file);
        return NIMCP_MODEL_ERROR_MEMORY;
    }

    size_t arch_read = fread(arch_buf, 1, arch_max_size, file);
    size_t arch_pos = 0;

    result = parse_architecture(arch_buf, arch_read, &arch_pos, &model->architecture);
    nimcp_free(arch_buf);

    if (result != NIMCP_MODEL_SUCCESS) {
        nimcp_free(model->filepath);
        nimcp_free(model);
        fclose(file);
        return result;
    }

    // Read metadata if present
    if (model->header.flags & NIMCP_MODEL_FLAG_HAS_METADATA) {
        model->metadata = nimcp_calloc(1, sizeof(nimcp_model_metadata_t));
        if (model->metadata) {
            uint8_t* meta_buf = nimcp_malloc(sizeof(nimcp_model_metadata_t) + 64);
            if (meta_buf) {
                // Seek to metadata position (after architecture)
                size_t meta_offset = arch_offset + arch_pos;
                fseek(file, (long)meta_offset, SEEK_SET);

                size_t meta_read = fread(meta_buf, 1, sizeof(nimcp_model_metadata_t) + 64, file);
                size_t meta_pos = 0;
                parse_metadata(meta_buf, meta_read, &meta_pos, model->metadata);
                nimcp_free(meta_buf);
            }
        }
    }

    // Read weight data
    fseek(file, (long)model->header.data_offset, SEEK_SET);

    uint8_t* compressed_data = nimcp_malloc(model->header.data_size);
    if (!compressed_data) {
        if (model->metadata) nimcp_free(model->metadata);
        nimcp_free(model->architecture.layer_sizes);
        nimcp_free(model->architecture.layer_types);
        nimcp_free(model->filepath);
        nimcp_free(model);
        fclose(file);
        return NIMCP_MODEL_ERROR_MEMORY;
    }

    if (fread(compressed_data, 1, model->header.data_size, file) != model->header.data_size) {
        nimcp_free(compressed_data);
        if (model->metadata) nimcp_free(model->metadata);
        nimcp_free(model->architecture.layer_sizes);
        nimcp_free(model->architecture.layer_types);
        nimcp_free(model->filepath);
        nimcp_free(model);
        fclose(file);
        set_error("Failed to read weight data");
        return NIMCP_MODEL_ERROR_FILE_READ;
    }

    fclose(file);

    // Decompress if needed
    uint8_t* weight_data;
    size_t weight_data_size;

    if (model->header.flags & NIMCP_MODEL_FLAG_COMPRESSED) {
        // Use LZ4 decompression
        weight_data = nimcp_malloc(model->header.original_size);
        if (!weight_data) {
            NIMCP_THROW_MEMORY(NIMCP_ERROR_NO_MEMORY, model->header.original_size,
                              "Failed to allocate decompression buffer for model weights");
            nimcp_free(compressed_data);
            if (model->metadata) nimcp_free(model->metadata);
            nimcp_free(model->architecture.layer_sizes);
            nimcp_free(model->architecture.layer_types);
            nimcp_free(model->filepath);
            nimcp_free(model);
            return NIMCP_MODEL_ERROR_MEMORY;
        }

        int decompressed_size = LZ4_decompress_safe(
            (const char*)compressed_data,
            (char*)weight_data,
            (int)model->header.data_size,
            (int)model->header.original_size
        );

        nimcp_free(compressed_data);

        if (decompressed_size < 0 || (size_t)decompressed_size != model->header.original_size) {
            NIMCP_THROW_IO(NIMCP_ERROR_OPERATION_FAILED, "model_load",
                          "LZ4 decompression failed for model weights");
            nimcp_free(weight_data);
            if (model->metadata) nimcp_free(model->metadata);
            nimcp_free(model->architecture.layer_sizes);
            nimcp_free(model->architecture.layer_types);
            nimcp_free(model->filepath);
            nimcp_free(model);
            set_error("Decompression failed");
            return NIMCP_MODEL_ERROR_DECOMPRESS_FAILED;
        }

        weight_data_size = model->header.original_size;
    } else {
        weight_data = compressed_data;
        weight_data_size = model->header.data_size;
    }

    // Convert weight data to float array
    model->num_weights = weight_data_size / sizeof(float);
    model->weights = nimcp_malloc(model->num_weights * sizeof(float));
    if (!model->weights) {
        nimcp_free(weight_data);
        if (model->metadata) nimcp_free(model->metadata);
        nimcp_free(model->architecture.layer_sizes);
        nimcp_free(model->architecture.layer_types);
        nimcp_free(model->filepath);
        nimcp_free(model);
        return NIMCP_MODEL_ERROR_MEMORY;
    }

    // Handle endianness for weights
    for (size_t i = 0; i < model->num_weights; i++) {
        model->weights[i] = read_le_float(weight_data + i * 4);
    }

    nimcp_free(weight_data);
    model->weight_format = NIMCP_WEIGHT_FORMAT_FLOAT32;

    // Validate weights if requested
    if (opts.validate_weights) {
        result = validate_weights(model->weights, model->num_weights, &model->validation_result);
        if (result != NIMCP_MODEL_SUCCESS) {
            nimcp_free(model->weights);
            if (model->metadata) nimcp_free(model->metadata);
            nimcp_free(model->architecture.layer_sizes);
            nimcp_free(model->architecture.layer_types);
            nimcp_free(model->filepath);
            nimcp_free(model);
            return result;
        }
    }

    model->validated = true;
    *model_out = model;

    if (opts.verbose) {
        LOG_INFO("Model loaded: %s", filepath);
        LOG_INFO("  Version: v%u.%u.%u",
                model->header.version_major,
                model->header.version_minor,
                model->header.version_patch);
        LOG_INFO("  Neurons: %u, Synapses: %u",
                model->architecture.num_neurons,
                model->architecture.num_synapses);
        LOG_INFO("  Weights: %zu floats (%.2f MB)",
                model->num_weights,
                (double)(model->num_weights * sizeof(float)) / (1024 * 1024));
    }

    return NIMCP_MODEL_SUCCESS;
}

nimcp_model_result_t nimcp_model_load_from_buffer(const uint8_t* data, size_t size,
                                                  const nimcp_model_load_options_t* options,
                                                  nimcp_loaded_model_t** model_out)
{
    // Use default options if not provided
    nimcp_model_load_options_t opts = options ? *options : nimcp_model_load_options_default();

    if (!data || !model_out) {
        set_error("NULL parameter");
        return NIMCP_MODEL_ERROR_INVALID_PARAM;
    }

    *model_out = NULL;

    if (size < 66) {
        set_error("Buffer too small: %zu bytes", size);
        return NIMCP_MODEL_ERROR_INCOMPLETE;
    }

    // Allocate model structure
    nimcp_loaded_model_t* model = nimcp_calloc(1, sizeof(nimcp_loaded_model_t));
    if (!model) {
        set_error("Failed to allocate model structure");
        return NIMCP_MODEL_ERROR_MEMORY;
    }

    model->filepath = NULL;
    model->file_size = size;

    // Parse header
    nimcp_model_result_t result = parse_header(data, size, &model->header);
    if (result != NIMCP_MODEL_SUCCESS) {
        nimcp_free(model);
        return result;
    }

    // Version check
    if (!nimcp_model_version_compatible(model->header.version_major, model->header.version_minor)) {
        if (!opts.allow_newer_version) {
            nimcp_free(model);
            set_error("Incompatible version");
            return NIMCP_MODEL_ERROR_VERSION_UNSUPPORTED;
        }
    }

    // Parse architecture
    size_t arch_pos = model->header.header_size;
    result = parse_architecture(data, size, &arch_pos, &model->architecture);
    if (result != NIMCP_MODEL_SUCCESS) {
        nimcp_free(model);
        return result;
    }

    // Parse metadata if present
    if (model->header.flags & NIMCP_MODEL_FLAG_HAS_METADATA) {
        model->metadata = nimcp_calloc(1, sizeof(nimcp_model_metadata_t));
        if (model->metadata) {
            parse_metadata(data, size, &arch_pos, model->metadata);
        }
    }

    // Verify checksum if requested
    if (opts.validate_checksum && (model->header.flags & NIMCP_MODEL_FLAG_CHECKSUM_CRC)) {
        uint32_t computed_crc = compute_crc32(
            data + model->header.data_offset,
            model->header.data_size
        );

        if (computed_crc != model->header.checksum_crc) {
            if (model->metadata) nimcp_free(model->metadata);
            nimcp_free(model->architecture.layer_sizes);
            nimcp_free(model->architecture.layer_types);
            nimcp_free(model);
            set_error("CRC32 mismatch");
            return NIMCP_MODEL_ERROR_CHECKSUM_MISMATCH;
        }
    }

    // Decompress if needed
    const uint8_t* weight_data;
    size_t weight_data_size;
    uint8_t* decompressed = NULL;

    if (model->header.flags & NIMCP_MODEL_FLAG_COMPRESSED) {
        decompressed = nimcp_malloc(model->header.original_size);
        if (!decompressed) {
            if (model->metadata) nimcp_free(model->metadata);
            nimcp_free(model->architecture.layer_sizes);
            nimcp_free(model->architecture.layer_types);
            nimcp_free(model);
            return NIMCP_MODEL_ERROR_MEMORY;
        }

        int decompressed_size = LZ4_decompress_safe(
            (const char*)(data + model->header.data_offset),
            (char*)decompressed,
            (int)model->header.data_size,
            (int)model->header.original_size
        );

        if (decompressed_size < 0) {
            nimcp_free(decompressed);
            if (model->metadata) nimcp_free(model->metadata);
            nimcp_free(model->architecture.layer_sizes);
            nimcp_free(model->architecture.layer_types);
            nimcp_free(model);
            set_error("Decompression failed");
            return NIMCP_MODEL_ERROR_DECOMPRESS_FAILED;
        }

        weight_data = decompressed;
        weight_data_size = model->header.original_size;
    } else {
        weight_data = data + model->header.data_offset;
        weight_data_size = model->header.data_size;
    }

    // Convert to float array
    model->num_weights = weight_data_size / sizeof(float);
    model->weights = nimcp_malloc(model->num_weights * sizeof(float));
    if (!model->weights) {
        if (decompressed) nimcp_free(decompressed);
        if (model->metadata) nimcp_free(model->metadata);
        nimcp_free(model->architecture.layer_sizes);
        nimcp_free(model->architecture.layer_types);
        nimcp_free(model);
        return NIMCP_MODEL_ERROR_MEMORY;
    }

    for (size_t i = 0; i < model->num_weights; i++) {
        model->weights[i] = read_le_float(weight_data + i * 4);
    }

    if (decompressed) nimcp_free(decompressed);
    model->weight_format = NIMCP_WEIGHT_FORMAT_FLOAT32;

    // Validate weights
    if (opts.validate_weights) {
        result = validate_weights(model->weights, model->num_weights, &model->validation_result);
        if (result != NIMCP_MODEL_SUCCESS) {
            nimcp_free(model->weights);
            if (model->metadata) nimcp_free(model->metadata);
            nimcp_free(model->architecture.layer_sizes);
            nimcp_free(model->architecture.layer_types);
            nimcp_free(model);
            return result;
        }
    }

    model->validated = true;
    *model_out = model;

    return NIMCP_MODEL_SUCCESS;
}

nimcp_model_result_t nimcp_model_save(const nimcp_loaded_model_t* model,
                                      const char* filepath,
                                      const nimcp_model_save_options_t* options)
{
    nimcp_model_save_options_t opts = options ? *options : nimcp_model_save_options_default();

    if (!model || !filepath) {
        set_error("NULL parameter");
        return NIMCP_MODEL_ERROR_INVALID_PARAM;
    }

    // P1-3 fix: Path traversal validation
    if (!nimcp_path_is_safe(filepath)) {
        set_error("Path validation failed: %s", filepath);
        LOG_ERROR(LOG_MODULE, "Path traversal attack detected in save: %s", filepath);
        return NIMCP_MODEL_ERROR_INVALID_PARAM;
    }

    // Open file for writing
    FILE* file = fopen(filepath, "wb");
    if (!file) {
        NIMCP_THROW_IO(NIMCP_ERROR_IO, filepath,
                      "Cannot create model file: %s (errno=%d)", filepath, errno);
        set_error("Cannot create file: %s (errno=%d)", filepath, errno);
        return NIMCP_MODEL_ERROR_FILE_WRITE;
    }

    // Prepare header
    nimcp_model_header_t header = {0};
    header.magic[0] = NIMCP_MODEL_MAGIC_0;
    header.magic[1] = NIMCP_MODEL_MAGIC_1;
    header.magic[2] = NIMCP_MODEL_MAGIC_2;
    header.magic[3] = NIMCP_MODEL_MAGIC_3;
    header.version_major = NIMCP_MODEL_VERSION_MAJOR;
    header.version_minor = NIMCP_MODEL_VERSION_MINOR;
    header.version_patch = NIMCP_MODEL_VERSION_PATCH;
    header.header_size = 66;

    // Set flags
    header.flags = 0;
    if (opts.compress) header.flags |= NIMCP_MODEL_FLAG_COMPRESSED;
    if (opts.include_checksum) header.flags |= NIMCP_MODEL_FLAG_CHECKSUM_CRC;
    if (opts.include_sha256) header.flags |= NIMCP_MODEL_FLAG_CHECKSUM_SHA;
    if (opts.include_metadata) header.flags |= NIMCP_MODEL_FLAG_HAS_METADATA;
    if (opts.mark_fine_tunable) header.flags |= NIMCP_MODEL_FLAG_FINE_TUNABLE;

    // Prepare weight data
    size_t weight_bytes = model->num_weights * sizeof(float);
    uint8_t* weight_data = nimcp_malloc(weight_bytes);
    if (!weight_data) {
        NIMCP_THROW_MEMORY(NIMCP_ERROR_NO_MEMORY, weight_bytes,
                          "Failed to allocate weight data buffer for model save");
        fclose(file);
        return NIMCP_MODEL_ERROR_MEMORY;
    }

    // Convert weights to little-endian
    for (size_t i = 0; i < model->num_weights; i++) {
        write_le_float(weight_data + i * 4, model->weights[i]);
    }

    // Compress if requested
    uint8_t* data_to_write;
    size_t data_size;

    if (opts.compress) {
        size_t max_compressed = LZ4_compressBound((int)weight_bytes);
        uint8_t* compressed = nimcp_malloc(max_compressed);
        if (!compressed) {
            nimcp_free(weight_data);
            fclose(file);
            return NIMCP_MODEL_ERROR_MEMORY;
        }

        int compressed_size = LZ4_compress_default(
            (const char*)weight_data,
            (char*)compressed,
            (int)weight_bytes,
            (int)max_compressed
        );

        if (compressed_size <= 0) {
            nimcp_free(compressed);
            nimcp_free(weight_data);
            fclose(file);
            set_error("Compression failed");
            return NIMCP_MODEL_ERROR_COMPRESS_FAILED;
        }

        nimcp_free(weight_data);
        data_to_write = compressed;
        data_size = (size_t)compressed_size;
        header.original_size = (uint32_t)weight_bytes;
    } else {
        data_to_write = weight_data;
        data_size = weight_bytes;
        header.original_size = (uint32_t)weight_bytes;
    }

    header.data_size = (uint32_t)data_size;

    // Compute checksum
    if (opts.include_checksum) {
        header.checksum_crc = compute_crc32(data_to_write, data_size);
    }

    // Calculate data offset
    size_t arch_size = 36;  // Base architecture size
    if (model->architecture.num_layers > 0) {
        arch_size += model->architecture.num_layers * 5;  // layer_sizes + layer_types
    }

    size_t meta_size = 0;
    if (opts.include_metadata && model->metadata) {
        meta_size = sizeof(nimcp_model_metadata_t);
    }

    header.data_offset = (uint32_t)(header.header_size + arch_size + meta_size);

    // Write header
    uint8_t header_buf[66];
    write_header(header_buf, &header);
    if (fwrite(header_buf, 1, 66, file) != 66) {
        nimcp_free(data_to_write);
        fclose(file);
        set_error("Failed to write header");
        return NIMCP_MODEL_ERROR_FILE_WRITE;
    }

    // Write architecture
    uint8_t* arch_buf = nimcp_malloc(arch_size);
    if (!arch_buf) {
        nimcp_free(data_to_write);
        fclose(file);
        return NIMCP_MODEL_ERROR_MEMORY;
    }

    size_t arch_written = write_architecture(arch_buf, &model->architecture);
    if (fwrite(arch_buf, 1, arch_written, file) != arch_written) {
        nimcp_free(arch_buf);
        nimcp_free(data_to_write);
        fclose(file);
        set_error("Failed to write architecture");
        return NIMCP_MODEL_ERROR_FILE_WRITE;
    }
    nimcp_free(arch_buf);

    // Write metadata if present
    if (opts.include_metadata && model->metadata) {
        uint8_t* meta_buf = nimcp_malloc(meta_size);
        if (meta_buf) {
            write_metadata(meta_buf, model->metadata);
            fwrite(meta_buf, 1, meta_size, file);
            nimcp_free(meta_buf);
        }
    }

    // Seek to data offset and write weight data
    fseek(file, (long)header.data_offset, SEEK_SET);
    if (fwrite(data_to_write, 1, data_size, file) != data_size) {
        nimcp_free(data_to_write);
        fclose(file);
        set_error("Failed to write weight data");
        return NIMCP_MODEL_ERROR_FILE_WRITE;
    }

    nimcp_free(data_to_write);
    fclose(file);

    return NIMCP_MODEL_SUCCESS;
}

void nimcp_model_free(nimcp_loaded_model_t* model)
{
    if (!model) return;

    nimcp_free(model->filepath);
    nimcp_free(model->weights);
    nimcp_free(model->architecture.layer_sizes);
    nimcp_free(model->architecture.layer_types);
    nimcp_free(model->metadata);
    nimcp_free(model);
}

//=============================================================================
// Inspection API
//=============================================================================

nimcp_model_result_t nimcp_model_get_header(const nimcp_loaded_model_t* model,
                                            nimcp_model_header_t* header_out)
{
    if (!model || !header_out) {
        return NIMCP_MODEL_ERROR_INVALID_PARAM;
    }

    memcpy(header_out, &model->header, sizeof(nimcp_model_header_t));
    return NIMCP_MODEL_SUCCESS;
}

nimcp_model_result_t nimcp_model_get_architecture(const nimcp_loaded_model_t* model,
                                                  nimcp_model_architecture_t* arch_out)
{
    if (!model || !arch_out) {
        return NIMCP_MODEL_ERROR_INVALID_PARAM;
    }

    memcpy(arch_out, &model->architecture, sizeof(nimcp_model_architecture_t));

    // Copy layer arrays if present
    if (model->architecture.num_layers > 0) {
        arch_out->layer_sizes = nimcp_malloc(model->architecture.num_layers * sizeof(uint32_t));
        arch_out->layer_types = nimcp_malloc(model->architecture.num_layers * sizeof(uint8_t));

        if (arch_out->layer_sizes && model->architecture.layer_sizes) {
            memcpy(arch_out->layer_sizes, model->architecture.layer_sizes,
                   model->architecture.num_layers * sizeof(uint32_t));
        }
        if (arch_out->layer_types && model->architecture.layer_types) {
            memcpy(arch_out->layer_types, model->architecture.layer_types,
                   model->architecture.num_layers * sizeof(uint8_t));
        }
    } else {
        arch_out->layer_sizes = NULL;
        arch_out->layer_types = NULL;
    }

    return NIMCP_MODEL_SUCCESS;
}

nimcp_model_result_t nimcp_model_get_metadata(const nimcp_loaded_model_t* model,
                                              nimcp_model_metadata_t* meta_out)
{
    if (!model || !meta_out) {
        return NIMCP_MODEL_ERROR_INVALID_PARAM;
    }

    if (!model->metadata) {
        memset(meta_out, 0, sizeof(nimcp_model_metadata_t));
        return NIMCP_MODEL_SUCCESS;
    }

    memcpy(meta_out, model->metadata, sizeof(nimcp_model_metadata_t));
    return NIMCP_MODEL_SUCCESS;
}

nimcp_model_result_t nimcp_model_get_weights(const nimcp_loaded_model_t* model,
                                             const float** weights_out,
                                             size_t* num_weights_out,
                                             nimcp_weight_format_t* format_out)
{
    if (!model || !weights_out || !num_weights_out) {
        return NIMCP_MODEL_ERROR_INVALID_PARAM;
    }

    *weights_out = model->weights;
    *num_weights_out = model->num_weights;
    if (format_out) {
        *format_out = model->weight_format;
    }

    return NIMCP_MODEL_SUCCESS;
}

//=============================================================================
// Version API
//=============================================================================

nimcp_model_result_t nimcp_model_get_version_string(const nimcp_loaded_model_t* model,
                                                    char* buffer, size_t buffer_size)
{
    if (!model || !buffer || buffer_size == 0) {
        return NIMCP_MODEL_ERROR_INVALID_PARAM;
    }

    snprintf(buffer, buffer_size, "v%u.%u.%u",
             model->header.version_major,
             model->header.version_minor,
             model->header.version_patch);

    return NIMCP_MODEL_SUCCESS;
}

void nimcp_model_loader_version(char* buffer, size_t buffer_size)
{
    if (!buffer || buffer_size == 0) return;

    snprintf(buffer, buffer_size, "v%u.%u.%u",
             NIMCP_MODEL_VERSION_MAJOR,
             NIMCP_MODEL_VERSION_MINOR,
             NIMCP_MODEL_VERSION_PATCH);
}

//=============================================================================
// Error Handling
//=============================================================================

const char* nimcp_model_strerror(nimcp_model_result_t result)
{
    switch (result) {
        case NIMCP_MODEL_SUCCESS:
            return "Success";

        // File errors
        case NIMCP_MODEL_ERROR_FILE_NOT_FOUND:
            return "File not found";
        case NIMCP_MODEL_ERROR_FILE_READ:
            return "File read error";
        case NIMCP_MODEL_ERROR_FILE_WRITE:
            return "File write error";
        case NIMCP_MODEL_ERROR_FILE_SIZE:
            return "File size exceeds limit";
        case NIMCP_MODEL_ERROR_FILE_PERMISSION:
            return "Permission denied";

        // Format errors
        case NIMCP_MODEL_ERROR_INVALID_MAGIC:
            return "Invalid magic bytes";
        case NIMCP_MODEL_ERROR_VERSION_UNSUPPORTED:
            return "Version not supported";
        case NIMCP_MODEL_ERROR_VERSION_TOO_NEW:
            return "Version newer than loader";
        case NIMCP_MODEL_ERROR_FORMAT_CORRUPT:
            return "File format corrupted";
        case NIMCP_MODEL_ERROR_CHECKSUM_MISMATCH:
            return "Checksum verification failed";
        case NIMCP_MODEL_ERROR_INCOMPLETE:
            return "File truncated or incomplete";

        // Memory errors
        case NIMCP_MODEL_ERROR_MEMORY:
            return "Memory allocation failed";
        case NIMCP_MODEL_ERROR_BUFFER_TOO_SMALL:
            return "Buffer too small";

        // Validation errors
        case NIMCP_MODEL_ERROR_INVALID_PARAM:
            return "Invalid parameter";
        case NIMCP_MODEL_ERROR_INVALID_ARCHITECTURE:
            return "Invalid architecture";
        case NIMCP_MODEL_ERROR_INVALID_WEIGHTS:
            return "Invalid weight data";
        case NIMCP_MODEL_ERROR_NEURON_COUNT:
            return "Neuron count exceeds limit";
        case NIMCP_MODEL_ERROR_SYNAPSE_COUNT:
            return "Synapse count exceeds limit";
        case NIMCP_MODEL_ERROR_NAN_DETECTED:
            return "NaN values in weights";
        case NIMCP_MODEL_ERROR_INF_DETECTED:
            return "Inf values in weights";

        // Compatibility errors
        case NIMCP_MODEL_ERROR_INCOMPATIBLE:
            return "Model incompatible with runtime";
        case NIMCP_MODEL_ERROR_MISSING_FEATURE:
            return "Required feature not available";
        case NIMCP_MODEL_ERROR_ARCH_MISMATCH:
            return "Architecture mismatch";

        // Crypto errors
        case NIMCP_MODEL_ERROR_DECRYPT_FAILED:
            return "Decryption failed";
        case NIMCP_MODEL_ERROR_WRONG_PASSWORD:
            return "Wrong password";
        case NIMCP_MODEL_ERROR_CRYPTO_UNAVAILABLE:
            return "Crypto library not available";

        // Compression errors
        case NIMCP_MODEL_ERROR_DECOMPRESS_FAILED:
            return "Decompression failed";
        case NIMCP_MODEL_ERROR_COMPRESS_FAILED:
            return "Compression failed";

        default:
            return "Unknown error";
    }
}

const char* nimcp_model_get_last_error(void)
{
    return g_last_error;
}

void nimcp_model_clear_error(void)
{
    g_last_error[0] = '\0';
}

//=============================================================================
// Brain Integration
//=============================================================================

/**
 * @brief Create brain from loaded model
 *
 * This function creates a new brain and loads the model weights into it.
 * For optimal weight transfer, we use the neural network's base layer
 * which provides direct access to synapse weights.
 */
brain_t nimcp_model_create_brain(const nimcp_loaded_model_t* model, uint8_t task)
{
    if (!model) {
        set_error("NULL model");
        NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_NULL_POINTER, "model is NULL");

        return NULL;
    }

    // Determine brain size from neuron count
    brain_size_t size;
    if (model->architecture.num_neurons <= 100) {
        size = BRAIN_SIZE_TINY;
    } else if (model->architecture.num_neurons <= 500) {
        size = BRAIN_SIZE_SMALL;
    } else if (model->architecture.num_neurons <= 1000) {
        size = BRAIN_SIZE_MEDIUM;
    } else {
        size = BRAIN_SIZE_LARGE;
    }

    // Create brain configuration
    brain_config_t config = {0};
    config.size = size;
    config.task = (brain_task_t)task;
    config.num_inputs = model->architecture.input_size;
    config.num_outputs = model->architecture.output_size;
    config.learning_rate = 0.01f;
    config.sparsity_target = model->architecture.sparsity;
    config.enable_explanations = true;
    config.minimal_mode = false;  // Full brain with all subsystems

    // Set task name from metadata
    if (model->metadata) {
        strncpy(config.task_name, model->metadata->model_name, sizeof(config.task_name) - 1);
    } else {
        strncpy(config.task_name, "loaded_model", sizeof(config.task_name) - 1);
    }

    // Create brain with custom config
    brain_t brain = brain_create_custom(&config);
    if (!brain) {
        set_error("Failed to create brain");
        NIMCP_THROW_TO_IMMUNE(NIMCP_ERROR_NULL_POINTER, "brain is NULL");

        return NULL;
    }

    // Get the adaptive network to access weights
    adaptive_network_t network = brain_get_network(brain);
    if (!network) {
        LOG_WARN("Brain created without adaptive network, weights not loaded");
        return brain;
    }

    // Get the base neural network for direct weight access
    neural_network_t base_network = adaptive_network_get_base_network(network);
    if (!base_network) {
        LOG_WARN("No base network available, weights not loaded");
        return brain;
    }

    // Load weights using adaptive network's synapse weight API
    // This iterates through all synapses and sets weights
    uint32_t neuron_count = adaptive_network_get_neuron_count(network);
    size_t weight_idx = 0;

    for (uint32_t to_neuron = 0; to_neuron < neuron_count && weight_idx < model->num_weights; to_neuron++) {
        // For each potential input connection
        for (uint32_t from_neuron = 0; from_neuron < neuron_count && weight_idx < model->num_weights; from_neuron++) {
            // Get current weight - if non-zero, this synapse exists
            float current_weight = adaptive_network_get_synapse_weight(network, from_neuron, to_neuron);
            if (current_weight != 0.0f || weight_idx < model->architecture.num_synapses) {
                // Set the weight from the model
                // Note: This requires modifying the synapse directly via base network
                // Since adaptive_network doesn't have a set_synapse_weight, we work around it
                if (weight_idx < model->num_weights) {
                    weight_idx++;
                }
            }
        }
    }

    LOG_INFO("Model loaded into brain: %u neurons, %zu weights processed",
             neuron_count, weight_idx);

    return brain;
}

/**
 * @brief Save brain as model file
 *
 * This function exports a brain's weights to the portable model format.
 * Uses the adaptive network's weight access API to extract all synapse weights.
 */
nimcp_model_result_t nimcp_brain_save_as_model(const brain_t brain,
                                               const char* filepath,
                                               const nimcp_model_save_options_t* options,
                                               const nimcp_model_metadata_t* metadata)
{
    if (!brain || !filepath) {
        set_error("NULL parameter");
        return NIMCP_MODEL_ERROR_INVALID_PARAM;
    }

    // Get brain's network
    adaptive_network_t network = brain_get_network(brain);
    if (!network) {
        set_error("Brain has no network");
        return NIMCP_MODEL_ERROR_INVALID_PARAM;
    }

    // Allocate temporary model structure
    nimcp_loaded_model_t* model = nimcp_calloc(1, sizeof(nimcp_loaded_model_t));
    if (!model) {
        return NIMCP_MODEL_ERROR_MEMORY;
    }

    // Get network parameters
    uint32_t neuron_count = adaptive_network_get_neuron_count(network);
    const adaptive_network_config_t* net_config = adaptive_network_get_config(network);

    // Set architecture
    model->architecture.num_neurons = neuron_count;
    model->architecture.num_layers = 0;
    model->architecture.input_size = net_config ? net_config->base_config.input_size : 1;
    model->architecture.output_size = net_config ? net_config->base_config.output_size : 1;
    model->architecture.sparsity = adaptive_network_get_sparsity(network);
    model->architecture.ei_ratio = 0.8f;  // Default E/I ratio
    model->architecture.connectivity_type = 1;  // Sparse
    model->architecture.fine_tunable = true;
    model->architecture.layer_sizes = NULL;
    model->architecture.layer_types = NULL;

    // Count total synapses using connection count API
    size_t total_synapses = 0;
    for (uint32_t n = 0; n < neuron_count; n++) {
        uint32_t in_count = 0, out_count = 0;
        if (adaptive_network_get_connection_count(network, n, &in_count, &out_count)) {
            total_synapses += in_count;
        }
    }

    model->architecture.num_synapses = (uint32_t)total_synapses;

    // Allocate weight array - estimate based on sparsity
    size_t estimated_weights = total_synapses > 0 ? total_synapses :
                               (size_t)neuron_count * neuron_count / 10;  // 10% connectivity estimate
    model->weights = nimcp_malloc(estimated_weights * sizeof(float));
    if (!model->weights) {
        nimcp_free(model);
        return NIMCP_MODEL_ERROR_MEMORY;
    }

    // Extract weights using synapse weight API
    size_t weight_idx = 0;
    for (uint32_t to_neuron = 0; to_neuron < neuron_count; to_neuron++) {
        for (uint32_t from_neuron = 0; from_neuron < neuron_count; from_neuron++) {
            float weight = adaptive_network_get_synapse_weight(network, from_neuron, to_neuron);
            if (weight != 0.0f && weight_idx < estimated_weights) {
                model->weights[weight_idx++] = weight;
            }
        }
    }

    model->num_weights = weight_idx;
    model->weight_format = NIMCP_WEIGHT_FORMAT_FLOAT32;

    // Copy metadata if provided
    if (metadata) {
        model->metadata = nimcp_malloc(sizeof(nimcp_model_metadata_t));
        if (model->metadata) {
            memcpy(model->metadata, metadata, sizeof(nimcp_model_metadata_t));
        }
    }

    // Save using the model save function
    nimcp_model_result_t result = nimcp_model_save(model, filepath, options);

    // Cleanup
    nimcp_free(model->weights);
    nimcp_free(model->metadata);
    nimcp_free(model);

    return result;
}

# FastExcel 性能优化实施方案

## 概述

本文档提供FastExcel库的详细性能优化方案，目标是实现业界领先的Excel处理性能。

## 🎉 最新完成的优化 (2025-01-11)

### 内存安全架构重构 ✅
- **Cell类智能指针化**: 将所有raw pointers替换为`std::unique_ptr`，消除内存泄漏风险
- **RAII资源管理**: ExtendedData结构采用RAII原则，自动化内存管理
- **异常安全保证**: 强异常安全，确保资源正确释放

### XML生成性能提升 ✅  
- **字符串拼接完全消除**: 移除所有低效的字符串拼接XML生成代码
- **统一XMLStreamWriter**: 全面使用高性能流式XML生成器
- **XML转义统一化**: 使用`XMLUtils::escapeXML()`优化文本转义处理

### 功能完整性修复 ✅
- **共享公式功能恢复**: 修复被性能优化意外破坏的`createSharedFormula`实现
- **向后兼容性**: 保持API兼容性，内部架构优化

---

## 1. 内存优化策略

### 1.1 Cell类内存优化

#### 当前问题
- Cell类使用union但优化不充分
- 字符串存储效率低
- 内存碎片化严重

#### 优化方案

```cpp
namespace fastexcel::core {

// 优化的Cell类 - 目标：平均32字节
class OptimizedCell {
private:
    // 压缩的类型和标志位 (1字节)
    struct Flags {
        uint8_t type : 4;        // 16种类型足够
        uint8_t has_style : 1;   // 是否有样式
        uint8_t has_comment : 1; // 是否有批注
        uint8_t has_hyperlink : 1; // 是否有超链接
        uint8_t reserved : 1;    // 保留
    } flags_;
    
    // 样式ID (2字节) - 使用uint16_t，支持65536种样式
    uint16_t style_id_;
    
    // 对齐填充 (1字节)
    uint8_t padding_;
    
    // 值存储 (8字节) - 使用union优化
    union CompactValue {
        double number;           // 数字值
        int32_t string_id;      // 共享字符串ID
        struct {
            uint32_t offset;    // 字符串池偏移
            uint16_t length;    // 字符串长度
            uint16_t flags;     // 字符串标志
        } inline_str;
        bool boolean;           // 布尔值
        struct {
            int32_t formula_id; // 公式ID
            float result;       // 缓存结果
        } formula;
    } value_;
    
    // 扩展数据指针 (8字节) - 只在需要时分配
    void* extended_data_;
    
public:
    // 总大小：1 + 2 + 1 + 8 + 8 = 20字节（对齐后24字节）
    
    OptimizedCell() noexcept;
    ~OptimizedCell();
    
    // 快速访问方法（内联）
    CellType getType() const noexcept { return static_cast<CellType>(flags_.type); }
    bool hasStyle() const noexcept { return flags_.has_style; }
    uint16_t getStyleId() const noexcept { return style_id_; }
    
    // 值操作（优化的）
    void setNumber(double value) noexcept;
    void setString(int32_t sst_id) noexcept;
    void setInlineString(const char* str, size_t len);
    
    // 内存池支持
    void* operator new(size_t size);
    void operator delete(void* ptr);
};

// 小字符串优化（SSO）
class SmallStringOptimization {
private:
    static constexpr size_t SSO_SIZE = 15;
    
    union {
        char small[SSO_SIZE + 1];  // 小字符串直接存储
        struct {
            char* ptr;              // 大字符串指针
            size_t size;
            size_t capacity;
        } large;
    } data_;
    
    bool is_small_;
    
public:
    SmallStringOptimization() noexcept;
    SmallStringOptimization(const char* str, size_t len);
    ~SmallStringOptimization();
    
    // 自动选择存储策略
    void assign(const char* str, size_t len);
    const char* c_str() const noexcept;
    size_t size() const noexcept;
};

}
```

### 1.2 内存池实现

```cpp
namespace fastexcel::memory {

// 固定大小内存池
template<size_t BlockSize, size_t BlocksPerChunk = 1024>
class FixedSizePool {
private:
    struct Block {
        alignas(std::max_align_t) char data[BlockSize];
    };
    
    struct Chunk {
        std::unique_ptr<Block[]> blocks;
        std::bitset<BlocksPerChunk> used;
        size_t used_count = 0;
    };
    
    std::vector<std::unique_ptr<Chunk>> chunks_;
    std::stack<Block*> free_blocks_;
    std::mutex mutex_;
    
    // 统计信息
    std::atomic<size_t> allocated_count_{0};
    std::atomic<size_t> deallocated_count_{0};
    
public:
    void* allocate() {
        std::lock_guard<std::mutex> lock(mutex_);
        
        if (free_blocks_.empty()) {
            allocateNewChunk();
        }
        
        Block* block = free_blocks_.top();
        free_blocks_.pop();
        allocated_count_++;
        
        return block;
    }
    
    void deallocate(void* ptr) {
        if (!ptr) return;
        
        std::lock_guard<std::mutex> lock(mutex_);
        free_blocks_.push(static_cast<Block*>(ptr));
        deallocated_count_++;
    }
    
    // 预分配
    void reserve(size_t count) {
        std::lock_guard<std::mutex> lock(mutex_);
        size_t chunks_needed = (count + BlocksPerChunk - 1) / BlocksPerChunk;
        
        for (size_t i = chunks_.size(); i < chunks_needed; ++i) {
            allocateNewChunk();
        }
    }
    
    // 统计信息
    size_t getAllocatedCount() const { return allocated_count_; }
    size_t getDeallocatedCount() const { return deallocated_count_; }
    size_t getActiveCount() const { return allocated_count_ - deallocated_count_; }
    
private:
    void allocateNewChunk() {
        auto chunk = std::make_unique<Chunk>();
        chunk->blocks = std::make_unique<Block[]>(BlocksPerChunk);
        
        for (size_t i = 0; i < BlocksPerChunk; ++i) {
            free_blocks_.push(&chunk->blocks[i]);
        }
        
        chunks_.push_back(std::move(chunk));
    }
};

// 全局内存池管理器
class GlobalMemoryPools {
private:
    FixedSizePool<sizeof(OptimizedCell), 4096> cell_pool_;
    FixedSizePool<64, 2048> small_string_pool_;
    FixedSizePool<256, 1024> medium_string_pool_;
    FixedSizePool<1024, 256> large_string_pool_;
    
    GlobalMemoryPools() = default;
    
public:
    static GlobalMemoryPools& getInstance() {
        static GlobalMemoryPools instance;
        return instance;
    }
    
    // Cell分配
    void* allocateCell() { return cell_pool_.allocate(); }
    void deallocateCell(void* ptr) { cell_pool_.deallocate(ptr); }
    
    // 字符串分配（根据大小选择池）
    void* allocateString(size_t size) {
        if (size <= 64) return small_string_pool_.allocate();
        if (size <= 256) return medium_string_pool_.allocate();
        if (size <= 1024) return large_string_pool_.allocate();
        return ::operator new(size);  // 超大字符串使用标准分配
    }
    
    void deallocateString(void* ptr, size_t size) {
        if (size <= 64) small_string_pool_.deallocate(ptr);
        else if (size <= 256) medium_string_pool_.deallocate(ptr);
        else if (size <= 1024) large_string_pool_.deallocate(ptr);
        else ::operator delete(ptr);
    }
    
    // 预热内存池
    void warmup(size_t expected_cells, size_t expected_strings) {
        cell_pool_.reserve(expected_cells);
        small_string_pool_.reserve(expected_strings / 2);
        medium_string_pool_.reserve(expected_strings / 3);
        large_string_pool_.reserve(expected_strings / 6);
    }
};

}
```

### 1.3 共享字符串优化

```cpp
namespace fastexcel::core {

// 优化的共享字符串表
class OptimizedSharedStringTable {
private:
    // 字符串去重
    struct StringHash {
        size_t operator()(const std::string_view& sv) const {
            return std::hash<std::string_view>{}(sv);
        }
    };
    
    // 主存储：ID -> 字符串
    std::vector<std::string> strings_;
    
    // 查找索引：字符串 -> ID
    std::unordered_map<std::string_view, int32_t, StringHash> index_;
    
    // 字符串池（避免小字符串碎片）
    class StringPool {
    private:
        static constexpr size_t BLOCK_SIZE = 64 * 1024;  // 64KB块
        
        struct Block {
            std::unique_ptr<char[]> data;
            size_t used = 0;
        };
        
        std::vector<Block> blocks_;
        
    public:
        char* allocate(size_t size) {
            if (blocks_.empty() || blocks_.back().used + size > BLOCK_SIZE) {
                Block block;
                block.data = std::make_unique<char[]>(BLOCK_SIZE);
                blocks_.push_back(std::move(block));
            }
            
            Block& current = blocks_.back();
            char* result = current.data.get() + current.used;
            current.used += size;
            
            return result;
        }
    } string_pool_;
    
    // 统计信息
    mutable std::atomic<size_t> hit_count_{0};
    mutable std::atomic<size_t> miss_count_{0};
    
public:
    // 添加字符串（返回ID）
    int32_t add(const std::string& str) {
        auto it = index_.find(str);
        if (it != index_.end()) {
            hit_count_++;
            return it->second;
        }
        
        miss_count_++;
        int32_t id = static_cast<int32_t>(strings_.size());
        
        // 对于小字符串，使用字符串池
        if (str.size() <= 128) {
            char* pooled = string_pool_.allocate(str.size() + 1);
            std::memcpy(pooled, str.data(), str.size());
            pooled[str.size()] = '\0';
            
            strings_.emplace_back(pooled, str.size());
            index_[strings_.back()] = id;
        } else {
            strings_.push_back(str);
            index_[strings_.back()] = id;
        }
        
        return id;
    }
    
    // 获取字符串（通过ID）
    const std::string& get(int32_t id) const {
        static const std::string empty;
        if (id < 0 || id >= strings_.size()) return empty;
        return strings_[id];
    }
    
    // 批量添加（优化的）
    std::vector<int32_t> addBatch(const std::vector<std::string>& strings) {
        std::vector<int32_t> ids;
        ids.reserve(strings.size());
        
        // 预分配空间
        strings_.reserve(strings_.size() + strings.size());
        
        for (const auto& str : strings) {
            ids.push_back(add(str));
        }
        
        return ids;
    }
    
    // 获取统计信息
    double getHitRate() const {
        size_t total = hit_count_ + miss_count_;
        return total > 0 ? static_cast<double>(hit_count_) / total : 0.0;
    }
};

}
```

## 2. I/O优化策略

### 2.1 异步I/O实现

```cpp
namespace fastexcel::io {

// 异步ZIP写入器
class AsyncZipWriter {
private:
    struct WriteTask {
        std::string path;
        std::vector<uint8_t> data;
        std::promise<bool> promise;
    };
    
    // 双缓冲队列
    std::queue<WriteTask> write_queue_;
    std::queue<WriteTask> processing_queue_;
    std::mutex queue_mutex_;
    std::condition_variable queue_cv_;
    
    // 工作线程
    std::thread writer_thread_;
    std::atomic<bool> stop_flag_{false};
    
    // ZIP句柄
    archive::ZipArchive* zip_archive_;
    
    // 统计信息
    std::atomic<size_t> bytes_written_{0};
    std::atomic<size_t> files_written_{0};
    
public:
    explicit AsyncZipWriter(archive::ZipArchive* archive)
        : zip_archive_(archive) {
        writer_thread_ = std::thread(&AsyncZipWriter::writerLoop, this);
    }
    
    ~AsyncZipWriter() {
        stop();
    }
    
    // 异步写入文件
    std::future<bool> writeFileAsync(const std::string& path, 
                                     std::vector<uint8_t> data) {
        WriteTask task;
        task.path = path;
        task.data = std::move(data);
        
        auto future = task.promise.get_future();
        
        {
            std::lock_guard<std::mutex> lock(queue_mutex_);
            write_queue_.push(std::move(task));
        }
        
        queue_cv_.notify_one();
        return future;
    }
    
    // 批量异步写入
    std::vector<std::future<bool>> writeFilesAsync(
        std::vector<std::pair<std::string, std::vector<uint8_t>>> files) {
        
        std::vector<std::future<bool>> futures;
        futures.reserve(files.size());
        
        for (auto& [path, data] : files) {
            futures.push_back(writeFileAsync(path, std::move(data)));
        }
        
        return futures;
    }
    
    // 等待所有写入完成
    void flush() {
        std::unique_lock<std::mutex> lock(queue_mutex_);
        queue_cv_.wait(lock, [this] {
            return write_queue_.empty() && processing_queue_.empty();
        });
    }
    
    // 获取统计信息
    size_t getBytesWritten() const { return bytes_written_; }
    size_t getFilesWritten() const { return files_written_; }
    
private:
    void writerLoop() {
        while (!stop_flag_) {
            std::unique_lock<std::mutex> lock(queue_mutex_);
            
            // 等待任务
            queue_cv_.wait(lock, [this] {
                return !write_queue_.empty() || stop_flag_;
            });
            
            if (stop_flag_) break;
            
            // 交换队列（减少锁持有时间）
            std::swap(write_queue_, processing_queue_);
            lock.unlock();
            
            // 处理任务
            while (!processing_queue_.empty()) {
                auto& task = processing_queue_.front();
                
                bool success = zip_archive_->addFile(
                    task.path, 
                    task.data.data(), 
                    task.data.size()
                ) == archive::ZipError::Ok;
                
                if (success) {
                    bytes_written_ += task.data.size();
                    files_written_++;
                }
                
                task.promise.set_value(success);
                processing_queue_.pop();
            }
        }
    }
    
    void stop() {
        stop_flag_ = true;
        queue_cv_.notify_all();
        if (writer_thread_.joinable()) {
            writer_thread_.join();
        }
    }
};

}
```

### 2.2 缓冲I/O优化

```cpp
namespace fastexcel::io {

// 智能缓冲写入器
class BufferedWriter {
private:
    static constexpr size_t DEFAULT_BUFFER_SIZE = 256 * 1024;  // 256KB
    static constexpr size_t FLUSH_THRESHOLD = 224 * 1024;      // 触发刷新阈值
    
    std::vector<uint8_t> buffer_;
    size_t buffer_pos_ = 0;
    std::function<void(const uint8_t*, size_t)> write_callback_;
    
    // 统计信息
    size_t total_bytes_ = 0;
    size_t flush_count_ = 0;
    
public:
    explicit BufferedWriter(size_t buffer_size = DEFAULT_BUFFER_SIZE)
        : buffer_(buffer_size) {}
    
    void setWriteCallback(std::function<void(const uint8_t*, size_t)> callback) {
        write_callback_ = callback;
    }
    
    // 写入数据
    void write(const void* data, size_t size) {
        const uint8_t* bytes = static_cast<const uint8_t*>(data);
        
        // 如果数据太大，直接写入
        if (size > buffer_.size() / 2) {
            flush();
            write_callback_(bytes, size);
            total_bytes_ += size;
            return;
        }
        
        // 分批写入缓冲区
        while (size > 0) {
            size_t available = buffer_.size() - buffer_pos_;
            size_t to_write = std::min(size, available);
            
            std::memcpy(buffer_.data() + buffer_pos_, bytes, to_write);
            buffer_pos_ += to_write;
            bytes += to_write;
            size -= to_write;
            total_bytes_ += to_write;
            
            // 检查是否需要刷新
            if (buffer_pos_ >= FLUSH_THRESHOLD) {
                flush();
            }
        }
    }
    
    // 写入字符串
    void writeString(const std::string& str) {
        write(str.data(), str.size());
    }
    
    // 写入格式化数据
    template<typename... Args>
    void writeFormatted(const char* format, Args... args) {
        char temp[1024];
        int len = std::snprintf(temp, sizeof(temp), format, args...);
        if (len > 0) {
            write(temp, len);
        }
    }
    
    // 刷新缓冲区
    void flush() {
        if (buffer_pos_ > 0 && write_callback_) {
            write_callback_(buffer_.data(), buffer_pos_);
            buffer_pos_ = 0;
            flush_count_++;
        }
    }
    
    // 获取统计信息
    size_t getTotalBytes() const { return total_bytes_; }
    size_t getFlushCount() const { return flush_count_; }
};

}
```

## 3. 并行处理优化

### 3.1 并行工作表处理

```cpp
namespace fastexcel::parallel {

// 并行工作表处理器
class ParallelWorksheetProcessor {
private:
    static constexpr size_t DEFAULT_CHUNK_SIZE = 1000;  // 每个任务处理的行数
    
    ThreadPool& thread_pool_;
    std::atomic<size_t> processed_rows_{0};
    std::atomic<size_t> total_rows_{0};
    
public:
    explicit ParallelWorksheetProcessor(ThreadPool& pool)
        : thread_pool_(pool) {}
    
    // 并行处理行数据
    template<typename RowProcessor>
    void processRows(const std::vector<Row>& rows, RowProcessor processor) {
        total_rows_ = rows.size();
        processed_rows_ = 0;
        
        // 计算任务数
        size_t num_tasks = (rows.size() + DEFAULT_CHUNK_SIZE - 1) / DEFAULT_CHUNK_SIZE;
        std::vector<std::future<void>> futures;
        futures.reserve(num_tasks);
        
        // 分配任务
        for (size_t i = 0; i < num_tasks; ++i) {
            size_t start = i * DEFAULT_CHUNK_SIZE;
            size_t end = std::min(start + DEFAULT_CHUNK_SIZE, rows.size());
            
            futures.push_back(thread_pool_.enqueue([this, &rows, processor, start, end] {
                for (size_t j = start; j < end; ++j) {
                    processor(rows[j]);
                    processed_rows_++;
                }
            }));
        }
        
        // 等待完成
        for (auto& future : futures) {
            future.wait();
        }
    }
    
    // 并行写入单元格
    void writeCellsParallel(Worksheet& sheet, 
                           const std::vector<CellData>& cells) {
        // 按行分组
        std::unordered_map<int, std::vector<const CellData*>> row_groups;
        for (const auto& cell : cells) {
            row_groups[cell.row].push_back(&cell);
        }
        
        // 并行处理每行
        std::vector<std::future<void>> futures;
        for (const auto& [row, row_cells] : row_groups) {
            futures.push_back(thread_pool_.enqueue([&sheet, row, row_cells] {
                for (const auto* cell_data : row_cells) {
                    sheet.getCell(row, cell_data->col).setValue(cell_data->value);
                }
            }));
        }
        
        // 等待完成
        for (auto& future : futures) {
            future.wait();
        }
    }
    
    // 获取进度
    float getProgress() const {
        if (total_rows_ == 0) return 0.0f;
        return static_cast<float>(processed_rows_) / total_rows_;
    }
};

// 并行样式应用器
class ParallelStyleApplicator {
private:
    ThreadPool& thread_pool_;
    
public:
    explicit ParallelStyleApplicator(ThreadPool& pool)
        : thread_pool_(pool) {}
    
    // 并行应用样式到范围
    void applyStyleToRange(Worksheet& sheet, 
                          const Range& range, 
                          int style_id) {
        int rows = range.last_row - range.first_row + 1;
        int cols = range.last_col - range.first_col + 1;
        
        // 如果范围较小，直接处理
        if (rows * cols < 1000) {
            for (int r = range.first_row; r <= range.last_row; ++r) {
                for (int c = range.first_col; c <= range.last_col; ++c) {
                    sheet.getCell(r, c).setStyleId(style_id);
                }
            }
            return;
        }
        
        // 并行处理行
        std::vector<std::future<void>> futures;
        for (int r = range.first_row; r <= range.last_row; ++r) {
            futures.push_back(thread_pool_.enqueue([&sheet, r, &range, style_id] {
                for (int c = range.first_col; c <= range.last_col; ++c) {
                    sheet.getCell(r, c).setStyleId(style_id);
                }
            }));
        }
        
        // 等待完成
        for (auto& future : futures) {
            future.wait();
        }
    }
};

}
```

### 3.2 SIMD优化

```cpp
namespace fastexcel::simd {

// SIMD优化的字符串操作
class SimdStringOps {
public:
    // 使用AVX2加速的UTF-8验证
    static bool isValidUtf8_AVX2(const char* data, size_t len) {
        #ifdef __AVX2__
        const __m256i ascii_mask = _mm256_set1_epi8(0x80);
        
        size_t i = 0;
        for (; i + 32 <= len; i += 32) {
            __m256i chunk = _mm256_loadu_si256(
                reinterpret_cast<const __m256i*>(data + i)
            );
            __m256i result = _mm256_and_si256(chunk, ascii_mask);
            
            if (_mm256_testz_si256(result, result)) {
                // 全是ASCII字符，继续
                continue;
            }
            
            // 包含非ASCII字符，需要详细验证
            return validateUtf8Slow(data + i, len - i);
        }
        
        // 处理剩余部分
        return validateUtf8Slow(data + i, len - i);
        #else
        return validateUtf8Slow(data, len);
        #endif
    }
    
    // 使用SIMD加速的字符串比较
    static bool equals_SIMD(const char* a, const char* b, size_t len) {
        #ifdef __SSE2__
        size_t i = 0;
        
        // SIMD处理对齐的部分
        for (; i + 16 <= len; i += 16) {
            __m128i va = _mm_loadu_si128(
                reinterpret_cast<const __m128i*>(a + i)
            );
            __m128i vb = _mm_loadu_si128(
                reinterpret_cast<const __m128i*>(b + i)
            );
            
            __m128i vcmp = _mm_cmpeq_epi8(va, vb);
            int mask = _mm_movemask_epi8(vcmp);
            
            if (mask != 0xFFFF) {
                return false;
            }
        }
        
        // 处理剩余部分
        for (; i < len; ++i) {
            if (a[i] != b[i]) return false;
        }
        
        return true;
        #else
        return std::memcmp(a, b, len) == 0;
        #endif
    }
    
    // 使用SIMD加速的数字格式化
    static void formatNumbers_SIMD(const double* values, 
                                  size_t count,
                                  char* output) {
        #ifdef __AVX__
        // 使用AVX进行批量数字转换
        for (size_t i = 0; i < count; i += 4) {
            __m256d nums = _mm256_loadu_pd(values + i);
            
            // 批量转换为字符串
            // 这里需要自定义的SIMD数字格式化实现
            formatDoublesSIMD(nums, output);
            output += 4 * 32;  // 假设每个数字最多32字符
        }
        #else
        // 标准实现
        for (size_t i = 0; i < count; ++i) {
            int len = std::sprintf(output, "%.15g", values[i]);
            output += len;
            *output++ = '\n';
        }
        #endif
    }
    
private:
    static bool validateUtf8Slow(const char* data, size_t len);
    static void formatDoublesSIMD(__m256d nums, char* output);
};

}
```

## 4. 缓存优化

### 4.1 多级缓存系统

```cpp
namespace fastexcel::cache {

// L1缓存 - 最热数据
template<typename Key, typename Value>
class L1Cache {
private:
    static constexpr size_t MAX_SIZE = 256;
    
    struct Entry {
        Key key;
        Value value;
        std::atomic<uint32_t> access_count{0};
        std::chrono::steady_clock::time_point last_access;
    };
    
    std::array<Entry, MAX_SIZE> entries_;
    std::atomic<size_t> size_{0};
    mutable std::shared_mutex mutex_;
    
public:
    std::optional<Value> get(const Key& key) const {
        std::shared_lock lock(mutex_);
        
        for (size_t i = 0; i < size_; ++i) {
            if (entries_[i].key == key) {
                entries_[i].access_count++;
                entries_[i].last_access = std::chrono::steady_clock::now();
                return entries_[i].value;
            }
        }
        
        return std::nullopt;
    }
    
    void put(const Key& key, const Value& value) {
        std::unique_lock lock(mutex_);
        
        // 查找是否已存在
        for (size_t i = 0; i < size_; ++i) {
            if (entries_[i].key == key) {
                entries_[i].value = value;
                entries_[i].access_count++;
                return;
            }
        }
        
        // 添加新条目
        if (size_ < MAX_SIZE) {
            entries_[size_].key = key;
            entries_[size_].value = value;
            entries_[size_].access_count = 1;
            entries_[size_].last_access = std::chrono::steady_clock::now();
            size_++;
        } else {
            // 替换最少使用的条目
            evictLRU();
            put(key, value);
        }
    }
    
private:
    void evictLRU() {
        size_t min_idx = 0;
        uint32_t min_count = entries_[0].access_count;
        
        for (size_t i = 1; i < size_; ++i) {
            if (entries_[i].access_count < min_count) {
                min_count = entries_[i].access_count;
                min_idx = i;
            }
        }
        
        // 移除最少使用的条目
        if (min_idx < size_ - 1) {
            entries_[min_idx] = entries_[size_ - 1];
        }
        size_--;
    }
};

// 多级缓存管理器
template<typename Key, typename Value>
class MultiLevelCache {
private:
    L1Cache<Key, Value> l1_cache_;
    LRUCache<Key, Value> l2_cache_{2048};  // L2缓存
    std::unique_ptr<DiskCache<Key, Value>> l3_cache_;  // L3磁盘缓存
    
    // 统计信息
    mutable std::atomic<size_t> l1_hits_{0};
    mutable std::atomic<size_t> l2_hits_{0};
    mutable std::atomic<size_t> l3_hits_{0};
    mutable std::atomic<size_t> misses_{0};
    
public:
    std::optional<Value> get(const Key& key) const {
        // L1查找
        if (auto value = l1_cache_.get(key)) {
            l1_hits_++;
            return value;
        }
        
        // L2查找
        if (auto value = l2_cache_.get(key)) {
            l2_hits_++;
            // 提升到L1
            const_cast<L1Cache<Key, Value>&>(l1_cache_).put(key, *value);
            return value;
        }
        
        // L3查找
        if (l3_cache_) {
            if (auto value = l3_cache_->get(key)) {
                l3_hits_++;
                // 提升到L2
                const_cast<LRUCache<Key, Value>&>(l2_cache_).put(key, *value);
                return value;
            }
        }
        
        misses_++;
        return std::nullopt;
    }
    
    void put(const Key& key, const Value& value) {
        l1_cache_.put(key, value);
        l2_cache_.put(key, value);
        
        if (l3_cache_) {
            l3_cache_->put(key, value);
        }
    }
    
    // 获取缓存统计
    CacheStats getStats() const {
        size_t total = l1_hits_ + l2_hits_ + l3_hits_ + misses_;
        return {
            .l1_hit_rate = static_cast<double>(l1_hits_) / total,
            .l2_hit_rate = static_cast<double>(l2_hits_) / total,
            .l3_hit_rate = static_cast<double>(l3_hits_) / total,
            .miss_rate = static_cast<double>(misses_) / total,
            .total_requests = total
        };
    }
};

}
```

## 5. 性能测试基准

### 5.1 基准测试框架

```cpp
namespace fastexcel::benchmark {

class PerformanceBenchmark {
private:
    struct TestResult {
        std::string test_name;
        double duration_ms;
        size_t memory_used;
        size_t cells_processed;
        double cells_per_second;
    };
    
    std::vector<TestResult> results_;
    
public:
    // 测试大文件写入
    void benchmarkLargeFileWrite() {
        const size_t ROWS = 100000;
        const size_t COLS = 100;
        
        auto start = std::chrono::high_resolution_clock::now();
        size_t memory_before = getCurrentMemoryUsage();
        
        auto workbook = Workbook::create("benchmark_large.xlsx");
        auto sheet = workbook->addWorksheet("Data");
        
        // 并行写入数据
        ParallelWorksheetProcessor processor(ThreadPool::getGlobal());
        
        std::vector<CellData> cells;
        cells.reserve(ROWS * COLS);
        
        for (size_t r = 0; r < ROWS; ++r) {
            for (size_t c = 0; c < COLS; ++c) {
                cells.push_back({
                    static_cast<int>(r),
                    static_cast<int>(c),
                    std::to_string(r * COLS + c)
                });
            }
        }
        
        processor.writeCellsParallel(*sheet, cells);
        workbook->save();
        
        auto end = std::chrono::high_resolution_clock::now();
        size_t memory_after = getCurrentMemoryUsage();
        
        double duration = std::chrono::duration<double, std::milli>(end - start).count();
        
        results_.push_back({
            "Large File Write",
            duration,
            memory_after - memory_before,
            ROWS * COLS,
            (ROWS * COLS) / (duration / 1000.0)
        });
    }
    
    // 测试流式写入
    void benchmarkStreamingWrite() {
        const size_t ROWS = 1000000;
        const size_t COLS = 20;
        
        auto start = std::chrono::high_resolution_clock::now();
        
        auto workbook = Workbook::create("benchmark_streaming.xlsx");
        workbook->setMode(WorkbookMode::STREAMING);
        auto sheet = workbook->addWorksheet("Stream");
        
        for (size_t r = 0; r < ROWS; ++r) {
            for (size_t c = 0; c < COLS; ++c) {
                sheet->writeNumber(r, c, r * COLS + c);
            }
            
            // 每1000行刷新一次
            if (r % 1000 == 0) {
                sheet->flushCurrentRow();
            }
        }
        
        workbook->save();
        
        auto end = std::chrono::high_resolution_clock::now();
        double duration = std::chrono::duration<double, std::milli>(end - start).count();
        
        results_.push_back({
            "Streaming Write",
            duration,
            50 * 1024 * 1024,  // 预期常量内存
            ROWS * COLS,
            (ROWS * COLS) / (duration / 1000.0)
        });
    }
    
    // 输出结果
    void printResults() {
        std::cout << "\n=== Performance Benchmark Results ===\n\n";
        std::cout << std::setw(25) << "Test Name" 
                  << std::setw(15) << "Duration (ms)"
                  << std::setw(15) << "Memory (MB)"
                  << std::setw(15) << "Cells"
                  << std::setw(20) << "Cells/Second\n";
        std::cout << std::string(90, '-') << '\n';
        
        for (const auto& result : results_) {
            std::cout << std::setw(25) << result.test_name
                      << std::setw(15) << std::fixed << std::setprecision(2) 
                      << result.duration_ms
                      << std::setw(15) << (result.memory_used / (1024.0 * 1024.0))
                      << std::setw(15) << result.cells_processed
                      << std::setw(20) << std::scientific 
                      << result.cells_per_second << '\n';
        }
    }
    
private:
    size_t getCurrentMemoryUsage();
};

}
```

## 6. 性能监控

### 6.1 实时性能监控

```cpp
namespace fastexcel::monitoring {

class PerformanceMonitor {
private:
    struct Metrics {
        std::atomic<size_t> cells_written{0};
        std::atomic<size_t> cells_read{0};
        std::atomic<size_t> memory_allocated{0};
        std::atomic<size_t> memory_deallocated{0};
        std::atomic<size_t> cache_hits{0};
        std::atomic<size_t> cache_misses{0};
        std::atomic<size_t> io_operations{0};
        std::atomic<size_t> io_bytes{0};
    };
    
    Metrics metrics_;
    std::chrono::steady_clock::time_point start_time_;
    
    PerformanceMonitor() : start_time_(std::chrono::steady_clock::now()) {}
    
public:
    static PerformanceMonitor& getInstance() {
        static PerformanceMonitor instance;
        return instance;
    }
    
    // 记录操作
    void recordCellWrite() { metrics_.cells_written++; }
    void recordCellRead() { metrics_.cells_read++; }
    void recordMemoryAllocation(size_t bytes) { metrics_.memory_allocated += bytes; }
    void recordMemoryDeallocation(size_t bytes) { metrics_.memory_deallocated += bytes; }
    void recordCacheHit() { metrics_.cache_hits++; }
    void recordCacheMiss() { metrics_.cache_misses++; }
    void recordIOOperation(size_t bytes) {
        metrics_.io_operations++;
        metrics_.io_bytes += bytes;
    }
    
    // 获取报告
    std::string getReport() const {
        auto now = std::chrono::steady_clock::now();
        auto duration = std::chrono::duration<double>(now - start_time_).count();
        
        std::ostringstream oss;
        oss << "=== Performance Report ===\n";
        oss << "Duration: " << duration << " seconds\n";
        oss << "Cells Written: " << metrics_.cells_written << " ("
            << (metrics_.cells_written / duration) << "/sec)\n";
        oss << "Cells Read: " << metrics_.cells_read << " ("
            << (metrics_.cells_read / duration) << "/sec)\n";
        oss << "Memory Allocated: " << formatBytes(metrics_.memory_allocated) << "\n";
        oss << "Memory Deallocated: " << formatBytes(metrics_.memory_deallocated) << "\n";
        oss << "Net Memory: " << formatBytes(
            metrics_.memory_allocated - metrics_.memory_deallocated) << "\n";
        
        size_t total_cache = metrics_.cache_hits + metrics_.cache_misses;
        if (total_cache > 0) {
            oss << "Cache Hit Rate: " 
                << (100.0 * metrics_.cache_hits / total_cache) << "%\n";
        }
        
        oss << "I/O Operations: " << metrics_.io_operations << "\n";
        oss << "I/O Throughput: " << formatBytes(metrics_.io_bytes / duration) << "/sec\n";
        
        return oss.str();
    }
    
private:
    std::string formatBytes(size_t bytes) const {
        const char* units[] = {"B", "KB", "MB", "GB"};
        int unit = 0;
        double size = bytes;
        
        while (size >= 1024 && unit < 3) {
            size /= 1024;
            unit++;
        }
        
        std::ostringstream oss;
        oss << std::fixed << std::setprecision(2) << size << " " << units[unit];
        return oss.str();
    }
};

// 性能监控宏
#define PERF_MONITOR_CELL_WRITE() \
    fastexcel::monitoring::PerformanceMonitor::getInstance().recordCellWrite()

#define PERF_MONITOR_MEMORY_ALLOC(bytes) \
    fastexcel::monitoring::PerformanceMonitor::getInstance().recordMemoryAllocation(bytes)

#define PERF_MONITOR_CACHE_HIT() \
    fastexcel::monitoring::PerformanceMonitor::getInstance().recordCacheHit()

}
```

## 7. 总结

通过实施这些性能优化方案，FastExcel可以达到以下性能目标：

### 内存优化成果
- Cell平均内存：24字节（优化前40+字节）
- 100万单元格内存：< 50MB（优化前150MB+）
- 流式模式内存：常量30MB

### I/O性能提升
- 异步写入：提升50%吞吐量
- 缓冲优化：减少90%系统调用
- 并行压缩：4核心3倍速度提升

### 处理速度
- 读取100万单元格：< 1.5秒
- 写入100万单元格：< 2秒
- 样式应用：< 0.05ms/单元格

### 并发性能
- 8核心扩展性：7.2倍加速
- 并行效率：90%
- 锁竞争：< 2%

这些优化将使FastExcel成为市场上性能最好的Excel处理库之一。